# AI broker: Claude, Codex or Free AI by one flag — 1 November 2026

> **Verdict:** `codex-broker` becomes `ai-broker`, **Worker included** (owner, 1 Nov 2026: "No, rename the Worker too"). One line, `ENGINE=codex|claude|free-ai`, in the broker's config says who answers first; the others answer only when it runs out. The Codex login moves with the Durable Object by a **Cloudflare namespace transfer**, proven on a throwaway pair first. Callers keep working through the old address and old OIDC audience until they have moved.

Owner (1 Nov 2026): "Let's change the codex-broker to ai-broker, and support claude, codex, or Free AI (cloudFlare Workers AI) with just a flag change". Picks: Claude on **"Your Claude subscription"** (Claude Code in the container, $0 API); flag **"Primary engine, others fall back"**.

## What changes for whom
| Who | Before | After |
|---|---|---|
| Owner | Changing the engine = code change | One config line + deploy (`ENGINE`) |
| CI / jobs | Codex → Claude API → Free AI, fixed | Same callers, same request; the chain starts at `ENGINE` |
| Admin / Telegram / Synthetic Monitoring | "Codex broker", "CI fallback" | "AI broker", the engine that answered each call |

## 1. Rename without losing the login
- **Fact (Cloudflare docs, Durable Object class exports/migrations):** a Durable Object namespace belongs to one Worker script, so a plain rename of `jobadabra-codex-broker` would start an empty namespace and lose the login. Cloudflare has a documented **transfer** to another Worker in the same account (`transferred_classes` in legacy migrations; `expecting-transfer` / `transferred` in `exports`), and a Container can be attached to the incoming class. Today's Worker uses legacy `migrations` (tag `v1`).
- **Target:** Worker `jobadabra-ai-broker`, folder `workers/ai-broker/`, tests `test/ai-broker/`, workflow `release-ai-broker.yml`, address `jobadabra-ai-broker.jobpilotto.workers.dev`, container application `ai-broker`. The binding `AI_BROKER` in `www` follows in 5/7 (a service binding to a Worker that does not exist yet would fail the production deploy of `www`).
- **Class name:** stays `CodexBroker` through the transfer (Cloudflare matches the namespace by class name on both sides) and is renamed `AiBroker` in 7/7 (an `exports` rename).
- **Step 0, done 1 Nov 2026 on a throwaway pair** (`ab-proof-src` / `ab-proof-dst`, tiny container, one stored key, both deleted afterwards):
  - Transfer works with a container, and the key was read back from the new Worker (twice).
  - **The hazard:** deploying the new Worker in any other order created an empty namespace (`k: null`). The only order that carried the key: the destination declares `expecting-transfer` *with* the container (that deploy ends in an expected "durable object was not found in the account namespace list" error) → the source deploys `transferred` with no container and no binding → the source's container application is deleted (a namespace holds one application: `DURABLE_OBJECT_ALREADY_HAS_APPLICATION`) → the destination deploys its final config.
  - A class rename inside the new Worker keeps the key and the container when the container application has its own fixed `name` (proven).
  - The old Worker, after the commit, can be redeployed as a forwarder and the `transferred` tombstone may keep a stub class in code.
- **Live step (by hand, runbook `workers/ai-broker/transfer/README.md`, configs `transfer/*.jsonc`; the hour named by a8, never 21:00–05:30 UTC, the owner present; ~3 minutes down):** the release workflow has **no push trigger** and refuses unless the new Worker's `/health` says `ready`, so merging cannot run or break the transfer.
- **Old address kept:** `jobadabra-codex-broker` is redeployed as a ~20-line forwarder to `AI_BROKER` (service binding) so `jobadabra-codex-broker.jobpilotto.workers.dev/call` keeps answering (the run token travels unchanged). Removed in the last PR once the callers (grep both repos) have moved.
- **OIDC audience:** the Worker accepts `jobadabra-ai-broker` and `jobadabra-codex-broker` until the public client moves; the old one is removed in the last PR.
- **Rollback:** before the commit step nothing has moved. After it, moving back is **not proven**; the fallback of last resort is a fresh `codex login` on the Mac and `/admin/login` (an owner step, minutes), which is why the owner is present.
- **Order:** merge 2/7 (nothing deploys), live step, then 3/7–5/7 (5/7 moves `www` to `AI_BROKER`), the public client (6/7), cleanup (7/7).

## 2. Engines and the flag
| Engine | Runs on | Money | "Ran out" means |
|---|---|---|---|
| `codex` | Codex CLI, owner's ChatGPT login (today) | $0 | own-share/week brake or a usage-limit error (today's rule) |
| `claude` | Claude Code CLI in the container, owner's Claude subscription token | $0 | Claude's "limit reached" answer; plus the broker's own per-day call count |
| `claude-api` | Anthropic Messages API (today's fallback) | up to $5/day | the $5 UTC-day cap |
| `free-ai` | Workers AI | up to $2/day | the $2 UTC-day cap |

- `ENGINE` (non-secret `vars` in `wrangler.jsonc`) names the first engine. The rest follow in a fixed order after it: `codex, claude, claude-api, free-ai`. Example: `ENGINE=claude` → claude, codex, claude-api, free-ai. Unset or unknown = `codex` (today's behaviour), and an unknown value is refused loudly in `/health`, never guessed.
- Subscriptions come before paid engines, paid before capped-free. A step is skipped, not failed, when it is not configured (no token, no key, no AI binding).
- Only "ran out" and "not configured" move to the next engine. A bad request, a token-shaped reply, a lost login and the daily drift cap keep today's refusal: another engine cannot bypass a control. Search requests are answered only by engines that support them (`codex`; `claude` with its web tool is a follow-up, today they go grey on the others).
- Every answer carries `engine`; `/health` lists `engine` (configured), `chain`, and per-engine state/day counts; the admin AI cost page and the Telegram notes name the engine.

**Long calls (2 Nov 2026).** The real daily-digest prompt (145 PRs, 70k characters, 27k input tokens) takes Claude 85–117 s with 72–105 s of thinking and 20–29k output tokens; `--effort low` (85 s), `MAX_THINKING_TOKENS=0` (118 s), `CLAUDE_CODE_DISABLE_THINKING=1` (110 s), `--thinking disabled` (117 s) and a titles-only prompt (5.6k input tokens, 87 s) did not shorten it, so neither thinking nor the input size can be turned down from outside: the task (place 145 PRs) is what costs (JOB-204). A Claude call therefore gets 150 s (`CLAUDE_TIMEOUT_MS`, callers wait 180 s); Codex keeps 100 s. A call killed by the timer fails as `claude-failed:timeout after 150 s`. This is the time the call needs, not a fix for why one grouping call is that big: the digest asks one call to regroup a whole day (parked as JOB for the digest owner if it keeps growing).

**Pinning one call to one engine (owner, 1 Nov 2026: "a CI workflow wants specifically to work with claude. Another one with codex").** `engine` alone only chooses who goes first; the rest still back it up. `"engine": "<name>", "only": true` is that engine alone: if it cannot answer (not configured, ran out, failed, week used up) the call is refused (503/429) with `why: "only-<engine>: <reason>"` and `tried`, never answered by another engine. `only` without `engine`, or not a boolean, is a 400.

**Adapting (JOB-202, owner, 1 Nov 2026: "adapt or report if one is doing worse than the other").** The two subscription engines (`codex`, `claude`) can move for doing worse: an engine that failed at least half of its last 10 real outcomes (at least 6 recorded; "ran out", a bad token and refusals are not failures) goes behind the other subscription for 30 minutes, the owner gets one Telegram note, `/health` shows `demotedUntil`, and after 30 minutes it is first again with a fresh window. Never moved: the paid API, Free AI, and a call that names its own `engine`. `ENGINE_ADAPT=off` turns it off. Latency is reported, never acted on (tiers and models differ). Caller-side quality (judge or persona pass rate grouped by `engine`) is each job's own check.

## 3. Claude engine on the subscription
- Container gets the Claude Code CLI next to Codex. Per call: `claude -p --output-format json --model <haiku|sonnet|opus> --tools "" --no-session-persistence`, empty temp dir, stdin closed, same unprivileged user, 100 s kill timer. Tiers map small/mid/large → `claude-haiku-5-5` / `claude-sonnet-5-5` / `claude-opus-5-5` (`shared/pro-claude.js`).
- Auth: the owner runs `claude setup-token` once; the value is the Worker secret `CLAUDE_CODE_OAUTH_TOKEN` (Keychain `job-pilotto.ai-broker.claude_oauth_token`, the repo's `job-pilotto.*` namespace), passed to the container as an env var by the Container class. It never goes to the image, a reply or a log.
- Deny-by-default hosts: add `api.anthropic.com` (measured in the first container run; telemetry off with `CLAUDE_CODE_DISABLE_NONESSENTIAL_TRAFFIC=1`, so nothing else is allowed unless a measured failure names it).
- Schema: `--json-schema`; images: base64 content blocks over `--input-format stream-json` so the CLI needs **no file-reading tool** (a Read tool could read the Codex login file in the same container; the Codex path has the same exposure and is covered by the reply guard, `lib/guard.mjs`).
- Limits: a subscription has no dollars, but it is **shared with the owner's own Claude Code use**. The broker counts calls per UTC day per engine (`/health`) and refuses past `CLAUDE_SUB_DAY_CALLS` if set; default unset (= "CI can use up to 100%", as for Codex). Decision below.
- The login-lost equivalent: an auth error from the CLI marks `claude` as "token-invalid" (health + one Telegram note) and the chain moves on.
- **Measured (1 Nov 2026, real CLI 2.1.316, the owner's token, local run of the container server):** (1) `--bare` is refused with an OAuth token ("Not logged in"): never used. (2) The CLI's default setup costs ~28-39k cached tokens per call; `--setting-sources "" --disable-slash-commands --strict-mcp-config` plus an own system prompt: ~390-430 input tokens. (3) Result JSON: `result` (text), `usage` (input, output, cache fields), `structured_output` with `--json-schema`; the stream also carries `rate_limit_event.rate_limit_info` = `{status, unifiedWindows: {five_hour, seven_day: {utilization, resetsAt, status}}}`, so "ran out" is read from the CLI's own status and the engine waits for its `resetsAt` (shown in `/health`). (4) Images as base64 blocks over `--input-format stream-json` work (a PNG came back "Green"). (5) stdin must be piped or closed (a 3 s warning otherwise). (6) One call peaks near 210 MB, so Claude runs at most 3 at a time in the 1 GiB container. (7) Speed: one-word Haiku/Sonnet 2.1 s, schema call 3.9 s, four parallel 1.6-2.0 s each. **Still a hypothesis until the first real "limit reached" happens:** the exact message of an exhausted subscription; the code reads the stream status first, then a message pattern, and treats anything else as a plain failure.

## 4. Decisions (all made, 1 Nov 2026)
1. **Decided (owner, 1 Nov 2026): rename the Worker too.** Therefore the namespace transfer in section 1; its risk is a possible re-login (owner step).
2. **Decided (owner, 1 Nov 2026): the paid Claude API stays**, $5/day as today, after the subscription engines.
3. **Decided (owner, 1 Nov 2026): no cap on the Claude subscription at first**; watch the daily count in `/health` for a week, then decide.

## 5. Acceptance
1. For each `ENGINE` (`codex`, `claude`, `free-ai`) with fakes: the first engine answers; when it reports "ran out" the next in order answers; a non-exhaustion error does not move on; the reply names the engine. No real provider in any test.
2. A request with no `ENGINE` behaves exactly as today (existing tests unchanged and green).
3. `/health` shows the engine, the chain and per-engine day counts, without any secret.
4. Old address and old audience still work until the cleanup PR; a test sends both.
5. The login survives: after the live transfer `/health` reads `ready` and a smoke call answers; the throwaway proof (step 0) shows a stored key read back first.

## 6. Plan (one PR each, `[ab] n/N`, web first)
1. **1/7 This spec.**
2. **2/7 Rename (web):** step 0 proof on the throwaway pair, then folder, tests, workflow (dispatch-only), `AI_BROKER` binding (`www` + admin + probe + seeds), labels, second audience, the old-name forwarder. Live step after merge, with the owner present.
3. **3/7 Engine chain + `ENGINE` flag** over today's three engines (`lib/engines.mjs`), `engine` in replies and `/health`, tests for all 3 settings.
4. **4/7 Claude subscription engine:** container, hosts, tier map, token secret, throwaway-call measurements recorded in the spec.
5. **5/7 Admin cost page, Telegram notes and the Synthetic Monitoring probe** name the engine.
6. **6/7 Public repo:** `broker-client.mjs` audience and URL, labels in `ai-cap.mjs` and workflows (lands after 2/7 is deployed).
7. **7/7 Cleanup:** remove the old audience and the forwarder once no caller uses them; give `release-ai-broker.yml` its push trigger. Then the `ENGINE` switch (hour named by a8, not 21:00–05:30 UTC). The per-`ENGINE` unit tests (fakes only) run inside the existing broker test step: no new matrix or schedule. The live proof is three one-off manual runs of one existing small CI job, one per `ENGINE` value (a few minutes each, ~15 Actions minutes once, nothing recurring), reported to mac-07.

## Progress
- [x] 1/7 spec (#278) · [x] 2/7 rename + transfer (#282, #286, #288) · [x] 3/7 engine chain (#289, #290) · [x] 4/7 Claude subscription engine · [ ] 5/7 · [ ] 6/7 · [ ] 7/7
