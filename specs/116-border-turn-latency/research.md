# Phase 0 Research: Border Agent Turn Latency

**Feature**: [spec.md](./spec.md) | **Date**: 2026-08-16

## Method

The spec's own "Context: what was measured" section established the symptom (26.8s fixed
preparation cost, 99.6% of a trivial turn) but not the mechanism. This session reproduced the
symptom live against the running Border (`openclaw-gateway.service`, PID 580, up since 12:47) and
traced it to a specific line of code by:

1. Reading the Border's own invocation path (`gateway.py::run_agent_turn()`).
2. Firing controlled trivial-answer turns against the live gateway and reading its own structured
   timing logs (`[trace:embedded-run] prep stages: ... bundle-tools:NNms`).
3. Decompiling the relevant sections of the vendored `openclaw` CLI/gateway bundle
   (`~/.nvm/versions/node/v25.1.0/lib/node_modules/openclaw/dist/*.js`) to find what `bundle-tools`
   actually does.
4. Reproducing the suspected sub-costs in isolation (direct MCP stdio handshakes, `uvx` cold-start,
   `openclaw mcp doctor --probe`) to rule out or confirm each one.
5. Stracing the isolated reproduction to find exactly where wall-clock time was spent.

## Finding 1 (confirmed): the 27s is spent purely in `bundle-tools`, every turn, with no reuse

Live gateway trace logs for five separate turns across 45+ minutes, all trivial two-character
answers, all against the same warm, long-running gateway process:

| runId (truncated) | sessionId | bundle-tools ms |
|---|---|---|
| 9f6e3c4a | 3e019d48 (fresh) | 28433 |
| f450b04e | f450b04e (fresh) | 26691 |
| bd632416 | f58afd44 (**reused** — 2nd turn, same session key) | 26732 |
| 9c9b8596 | f58afd44 (**reused** — 3rd turn, same session key) | 26558 |
| 27b0cad0 | 210ff945 (fresh) | 27186 |
| 024d7c1d | d8e91c45 (main direct WS session, not CLI) | 26646 |
| 0496dc96 | d8e91c45 (main direct WS session, not CLI, earlier turn) | 33399 |

A 2-hour survey of every turn logged by the gateway (any channel — CLI test turns, the Slack group
session, cron heartbeats, the main direct WS chat session) showed **16 of 16** turns paying between
26.5s and 33.4s in `bundle-tools`, with zero turns showing a materially lower cost. This directly
confirms the spec's Assumption ("the ~27s preparation cost is systemic... on multiple
conversations, on an idle machine") and rules out per-session amortization: **the same session key,
called twice in a row against a warm gateway, pays the full cost both times.** This contradicts a
plausible prior hypothesis (visible in the conversation history) that `mcp.sessionIdleTtlMs`
governs reuse — the session-level MCP runtime cache exists and is correctly keyed, but something
else destroys it after every single turn regardless of TTL.

## Finding 2 (confirmed): `cleanupBundleMcpOnRunEnd: true` forces teardown after every turn

Decompiling `agent-bundle-mcp-runtime-BkUYqKo5.js` (the module backing `bundle-tools`) found a
session-scoped runtime cache (`getOrCreateSessionMcpRuntime` / `runtimesBySessionId`) that is
designed to be reused across calls for the same `sessionId` — exactly the "reuse across requests"
mechanism FR-001 asks for, already built into OpenClaw. Its cache-hit path
(`agent-bundle-mcp-runtime-BkUYqKo5.js:1356-1364`) is cheap: an existing-runtime check plus
`markUsed()`, no rescan.

But `embedded-agent-Cv8lGIPa.js:4456` runs this on every attempt's `finally` block:

```js
if (params.cleanupBundleMcpOnRunEnd === true) await runAgentCleanupStep({
    ...
    cleanup: async () => {
        ...
        if (!await retireSessionMcpRuntimeForSessionKey({ sessionKey: params.sessionKey, ... }))
            await retireSessionMcpRuntime({ sessionId: params.sessionId, ... });
    }
});
```

`retireSessionMcpRuntime` disposes the cached runtime and deletes it from the map
(`agent-bundle-mcp-runtime-BkUYqKo5.js:1408-1421`). So whenever a caller sets
`cleanupBundleMcpOnRunEnd: true`, the very runtime that would have been reused on the next turn is
torn down at the end of the current one — guaranteeing the next turn starts cold, no matter how
fast it arrives or whether it reuses the same session key.

`agent-via-gateway-BB-FX7EM.js` — the module backing the `openclaw agent` CLI subcommand that
`gateway.py::run_agent_turn()` shells out to — sets this flag **unconditionally, in both of its
dispatch branches**:

```js
// line 435, gateway-RPC dispatch branch:
cleanupBundleMcpOnRunEnd: true,
// line 530, agentCliCommand wrapper (also sets it for the --local embedded path):
cleanupBundleMcpOnRunEnd: true,
```

There is no CLI flag to opt out. Every `openclaw agent ...` invocation — which is every single
Border-originated agent turn today, since `run_agent_turn()` is the sole invocation path used by
`chat.py`, `invocation.py`, and `service.py` — pays full teardown-and-rebuild, every time.

## Finding 3 (confirmed by contrast): OpenClaw's own internal code proves warm reuse works

`openclaw-tools-DnJ9m035.js:10183` (`runAgentStep`, backing the `sessions_send` tool that OpenClaw's
own agent uses to message another session) calls the identical gateway `agent` RPC method but
**omits `cleanupBundleMcpOnRunEnd` entirely**:

```js
const response = await agentStepDeps.callGateway({
    method: "agent",
    params: { message, sessionKey: params.sessionKey, idempotencyKey: stepIdem, deliver: false,
              sourceReplyDeliveryMode: "message_tool_only", channel, lane,
              extraSystemPrompt: params.extraSystemPrompt, inputProvenance },
    timeoutMs: 1e4
});
```

This is the load-bearing precedent: the gateway's own `agent` RPC method, called the same way, with
the same session-key-based runtime cache available, does **not** force teardown by default. The
flag is opt-in, and the CLI dispatch path opts in unconditionally where the internal tool-call path
does not. This is not a limitation of the gateway or the runtime cache — it is a specific choice
made in one specific call site (`agent-via-gateway-BB-FX7EM.js`) that the Border's CLI-based
invocation goes through.

## Finding 4 (confirmed, secondary): what `bundle-tools` actually rebuilds, and why it's slow

With the cache invalidated every turn, `getCatalog()` in `agent-bundle-mcp-runtime-BkUYqKo5.js`
runs from scratch. This does two expensive things:

1. **`loadMergedBundleMcpConfig` → `loadEnabledBundleMcpConfig` → `loadPluginManifestRegistryForPluginRegistry`**:
   discovers and merges MCP config contributed by every *enabled* OpenClaw plugin (3 of 69
   registered: `defenseclaw`, `memory-core`, `slack`), by walking the plugin manifest registry.
   Stracing an equivalent-cost CLI call (`openclaw mcp doctor pagerduty-mcp --probe`, which
   triggers the identical `createSessionMcpRuntime` → `getCatalog` path) during its slow window
   showed **79,090 `statx` and 19,721 `openat` syscalls** in a 24-second span, overwhelmingly
   against `.../openclaw/dist/extensions/` (226 hits) and — unexpectedly — `.../node_modules/kysely/dist/**`
   (1,000+ hits on `kysely/dist/package.json` alone), the query-builder library OpenClaw's own
   plugin/state-index SQLite layer depends on. This is Node's CommonJS/ESM module resolution walking
   the `kysely` package's many subpath exports on every dynamic `import()` triggered during registry
   loading — not a NetClaw-authored cost, but a real one paid on every turn because of Finding 2.
2. **Sequentially connecting every configured MCP server, one at a time**, per
   `agent-bundle-mcp-runtime-BkUYqKo5.js:1094` (`for (const [serverName, rawServer] of
   Object.entries(loaded.mcpServers))`) — a genuine serial `for` loop, not a `Promise.all`. Measured
   independently (a direct Python MCP-client script performing the same stdio handshake against all
   8 configured servers, sequentially, matching the code's own pattern): **5.15s summed / 6.17s wall
   clock** — real, but a minority of the 26.8s. `rag-mcp` (chromadb/sentence-transformers/torch
   imports) is the slowest single server at ~1.3s; the rest complete in 0.4–0.5s each.

Finding 4's two costs sum to roughly 6-8s of the 26.8s measured — real and worth fixing (FR-001's
"performed concurrently rather than one item at a time" applies directly to sub-finding 2), but they
do not explain the full 26.8s on their own, and critically **neither cost would matter if Finding 2
were fixed**, because a warm, reused runtime never re-pays either of them. Root-causing stopped once
Finding 2 was confirmed as sufficient: eliminating the forced teardown makes turns 2+ in a session
free of this entire category of cost, which is what FR-002 ("dominated by the actual work... not
fixed preparation") and SC-003 ("no repeated full preparation cost") actually require.

## Finding 5 (ruled out): PagerDuty's missing API key is not a contributor

Initial suspicion (visible in prior conversation exploration) was that `pagerduty-mcp` — the one
server missing its required `PAGERDUTY_USER_API_KEY` env var — might be hanging during connection
and inflating the total. Directly timed and stack-traced:

- `pagerduty-mcp` completes its full stdio handshake (spawn → initialize → tools/list) in
  **1.1–1.7 seconds** whether the key is absent, empty, a dummy value, or an unsubstituted
  `${PAGERDUTY_USER_API_KEY}` literal — it fails fast with a local `RuntimeError` before any network
  call, or (with a key present) makes one fast `401`-returning HTTP call and proceeds anyway
  (`pagerduty_mcp` logs a `WARNING` and continues; the MCP session still initializes with 101
  tools). This is not a slow path.
- `openclaw mcp doctor pagerduty-mcp --probe` in isolation *did* take ~26s — but stracing it showed
  the 24s gap was entirely *before* `uvx` was even spawned (module resolution/registry-scan cost,
  Finding 4), not inside the PagerDuty server's own startup. `openclaw mcp doctor rag-mcp --probe`
  (a server with no credential problem at all) showed the same ~26s-minus-actual-server-time pattern
  scaled to its own ~1.3s handshake, confirming the fixed cost is present regardless of which server
  is probed.

PagerDuty's missing credential is a legitimate configuration gap (worth fixing separately so the
tool doesn't silently degrade) but it is not part of this feature's root cause and FR-001–FR-018 do
not depend on resolving it.

## Decision

**Primary fix (addresses FR-001, FR-002, SC-001, SC-002, SC-003)**: Change
`gateway.py::run_agent_turn()`'s default dispatch mechanism from spawning the `openclaw agent` CLI
subprocess (which unconditionally sets `cleanupBundleMcpOnRunEnd: true`) to a persistent WebSocket
JSON-RPC connection to the same gateway, calling its `agent` method the same way OpenClaw's own
`runAgentStep`/`sessions_send` does — which does not force teardown and lets the existing,
already-correct session-scoped MCP runtime cache do its job. This is entirely a NetClaw-side change
(`gateway.py` is NetClaw's own file); it requires no modification to the vendored `openclaw`
package. `run_agent_turn()`'s public signature and return shape stay identical, so `chat.py`,
`invocation.py`, and `service.py` require zero changes (satisfies Constitution Principle XV).

**Secondary fix (addresses the residual few-seconds cost on genuinely cold turns — first request
after a Border restart, FR-004b)**: Parallelize the per-server MCP connection loop is OpenClaw's own
code (`agent-bundle-mcp-runtime-BkUYqKo5.js`), not NetClaw's, so it cannot be edited directly.
Where NetClaw *can* act — per FR-018's mandate to use every lever it controls — is: (a) file the
serial-loop and manifest-registry-scan costs as an evidenced upstream issue (satisfies FR-018's
"any residual portion... documented with reproducible evidence"), and (b) ensure the persisted
plugin registry (`openclaw plugins registry --refresh`) is kept current as part of Border
maintenance, since a stale/uncached registry is the more expensive path through Finding 4's first
sub-cost. This is a mitigation, not a structural fix — but the primary fix (Finding 2) makes it
irrelevant for every turn after the first in a session, which covers the overwhelming majority of
real traffic per the spec's own measurement (User Story 1, "staying in one conversation does not
amortize it" — after this fix, it does).

**Alternatives considered and rejected**:

- *Increasing `mcp.sessionIdleTtlMs`*: rejected — proven irrelevant by Finding 1's direct
  reproduction (raising TTL was tried and tested in prior exploration this session per the
  conversation history; two calls in immediate succession still paid full cost both times, because
  the runtime is force-retired at the *end* of each call, before TTL ever gets a chance to expire
  it).
- *Patching the vendored OpenClaw bundle directly* (e.g., flip `cleanupBundleMcpOnRunEnd` to `false`
  in `agent-via-gateway-BB-FX7EM.js`): rejected — this is a third-party npm-distributed dependency
  (`openclaw@2026.6.11`); patching its `dist/` output would be silently overwritten on the next
  `npm install -g openclaw` / version bump, is invisible to code review, and violates the spirit of
  Constitution Principle XV (no undocumented, unmaintainable fork of a shared dependency). The WS
  RPC approach achieves the identical effect (calling the gateway without the forcing flag) using
  the gateway's own supported, documented protocol.
- *Keep using the CLI but pass some hypothetical `--no-cleanup-mcp` flag*: rejected — no such flag
  exists in `agent-via-gateway-BB-FX7EM.js`'s option surface (confirmed by reading its full argument
  list); inventing one would again require patching the vendored dependency.
- *Pre-warming a single long-lived `openclaw agent` subprocess and piping turns into it via stdin*:
  rejected — the CLI's `agent` subcommand is designed for one-shot `--json` invocation per process
  (confirmed by reading its help text and dispatch code — there is no persistent-stdin-loop mode);
  building one would mean maintaining a bespoke protocol on top of a tool not designed for it, where
  the gateway's actual WS RPC protocol already exists and is exactly what `sessions_send` uses for
  this purpose.

## Post-implementation measurement (T019, live Border, 2026-08-16)

With the fix implemented and `netclaw-mesh.service` restarted to load it, `scripts/measure-turn-latency.py`
measured, against the live gateway:

| Measurement | Before (spec baseline) | After (measured) | Target | Met? |
|---|---|---|---|---|
| First turn, cold, new session | 37.9s | 34.6s | — (one-time cost, FR-004b) | N/A — see note below |
| Second turn, warm, same session | 37.9s (no amortization) | **6.08s** | SC-001: <12s | **YES — 6.2× improvement** |
| No repeated full-preparation cost | Failed (full cost every turn) | **Confirmed** — a 3-turn run in one session showed exactly ONE `[trace:embedded-run]` log line total; turns 2 and 3 never rebuilt the MCP tool set at all | SC-003 | **YES** |
| Fixed preparation time, cold turn | 26.8s | ~27.5s (unchanged) | SC-002: <3s | **NO** |

**SC-001 and SC-003 are met, with a large margin.** This is the fix's entire practical value: every
turn after the first in a session — which per the spec's own Context section is nearly all real
traffic ("staying in one conversation does not amortize it" was the old failure; it now does) — is
6× faster.

**SC-002, read literally (the fixed-preparation portion falls below 3 seconds), is NOT met.** The
~27s cost on a session's first turn is unchanged, because — per Finding 4 — that cost lives inside
OpenClaw's own vendored code (the plugin-manifest-registry scan and the serial per-server MCP
connect loop in `agent-bundle-mcp-runtime-BkUYqKo5.js`), which this feature correctly declined to
patch (Constitution Principle XV; see "Alternatives considered"). This is exactly the scenario
FR-018 anticipates: *"Any residual portion that provably requires a change outside NetClaw MUST be
documented with reproducible evidence, but does NOT excuse missing the targets."* The evidence is
recorded here; the target is honestly reported as not fully met by this pass. FR-004b's explicit
allowance ("a modest first-request warming cost... provided it is paid once") means this residual
cost is *tolerable* for the feature's actual user-facing goal, but it is not the same claim as
SC-002 being satisfied — Pass 3 (or a future pass) should decide whether to pursue the serial-loop
parallelization NetClaw *can* control (Finding 4, sub-cost 2 — measured independently at ~6s of the
~27s, a lever within NetClaw's reach since it is the connection loop in code NetClaw's config feeds
into, not the manifest scan itself) as a follow-up, since it was explicitly out of scope for this
implementation pass (tasks.md's Foundational phase built the dispatch fix only, not a parallelized
MCP-connect loop, which is upstream OpenClaw code NetClaw cannot directly modify).

**SC-004** (phone-question median improvement) could not be measured in this pass: the live host had
zero `n2n-edge`-tagged turns in its recent log window at measurement time (no phone traffic since the
last log rotation/service restart). This is an environmental gap, not a fix failure — the
measurement script (T018) is built and ready; Pass 3, once phone traffic resumes against the fixed
Border, should re-run it to populate this figure.

### `inputProvenance` correction (found during T025/T026 implementation)

The original contract draft (`contracts/gateway-ws-rpc.md`) proposed sending both `extraSystemPrompt`
and `inputProvenance: {"origin": "voice"}` in the RPC params. Reading the gateway's own
`normalizeInputProvenance` (`input-provenance-CQSqbDss.js`) during implementation showed
`inputProvenance.kind` is validated against a fixed enum (`external_user`/`inter_session`/
`internal_system`); an ad-hoc `origin` field is not a recognized shape and is silently dropped.
`inputProvenance` was removed from `_build_agent_rpc_params` — `extraSystemPrompt` alone is the real,
confirmed-working mechanism (verified live, see below). FR-013's origin-retention requirement is
satisfied by `gateway.py` logging `origin` itself via its own logger, not by round-tripping it
through the gateway. `contracts/gateway-ws-rpc.md` and the test suite were updated to match.

### US2 live verification (T028, live Border, 2026-08-16)

Two live checks confirmed `extraSystemPrompt` genuinely changes composition, not just in unit tests:

- A trivial question (`"What is 7 plus 5?"`, `origin="voice"`) returned `"12."` — plain, one
  fragment, no markup.
- A question **explicitly asking for headers and bullet points** (`"Tell me a fun fact about
  giraffes, with headers and bullet points please."`, `origin="voice"`) returned two plain sentences
  with zero markup — the voice-composition instruction correctly overrode an explicit contrary user
  request, which is the intended FR-010 behavior.

**One real edge case surfaced, not previously anticipated in the spec's own Edge Cases list**: a
`origin="voice"` request whose answer requires synthesizing genuinely large structured tool output
(a full multi-system "Border Health Status" query touching members, federation peers, and edge
nodes) returned a full multi-section markdown report — the same shape as the unmarked equivalent —
rather than 1-2 spoken sentences. The voice instruction was present in the request in both cases;
the model's own domain skill for that query type appears to prioritize faithfully presenting
complex structured data over the brevity instruction. This is a real tension inside FR-011 itself
("truthful and complete enough... where the full answer cannot fit, summarise honestly") for
genuinely multi-faceted answers, not a defect in `_build_agent_rpc_params` or the WS dispatch path
(both are confirmed working correctly by the two checks above). Documented here rather than
"fixed" — SC-007's 9-of-10 threshold explicitly anticipates some tries not landing perfectly;
whether a health-status-class query needs a stronger or more specific voice instruction is a
judgment call best made with real usage data in Pass 3, not guessed at here.

### T032 finding: there is no gateway-native "interactive" priority lane, and no NetClaw-authored background call site to prioritize against

Investigated the gateway's `lane` concept (`AGENT_LANE_NESTED`/`AGENT_LANE_CRON_NESTED`/
`AGENT_LANE_SUBAGENT`/`AGENT_LANE_CRON`, `lanes-CI0_P-yC.js`) expecting an "interactive" priority
value analogous to `runAgentStep`'s usage. It is not a priority scheduler: these lanes classify
*where a nested/subagent/cron run's session state lives* for isolation purposes, not queue order.
The `queued_behind_active_work` classification seen in gateway logs (research.md Finding 1's
`netclaw-heartbeat` evidence) is a **per-session-key** in-order message queue (a session processes
its own messages one at a time), not a cross-session global scheduler — confirmed by reading
`diagnostic-71wqFzEw.js`'s `queueDepth` tracking, which is scoped to one session's own state object.
`agents.defaults.maxConcurrent` (the one real cross-session concurrency knob,
`agent-limits-DGV0ALs8.js`) is unset in the live config, meaning unrelated sessions already run
fully concurrently today — exactly what T021 measured directly (two different session keys
completed in ~33s total, not ~66s).

**Separately, auditing every real call site of `run_agent_turn()`** (`chat.py`'s live peer chat,
`invocation.py`'s eN2N peer-initiated skill/knowledge requests, `service.py`'s `_edge_on_ask` — the
phone's own interactive "ask NetClaw" path — and `service.py`'s delegated-skill worker, which uses
`local=True` embedded mode and never goes through the WS RPC path at all) found **no
NetClaw-authored scheduled/background call site that competes with an interactive request today**.
The `netclaw-heartbeat` cron job visible in `openclaw cron list` runs entirely inside the OpenClaw
gateway's own cron subsystem (`agent:main:cron:netclaw-heartbeat:...` session keys) — it is not
dispatched through NetClaw's `gateway.py` at all, so there is nothing in this codebase for
`run_agent_turn()`'s callers to mark as "background" relative to it.

**Conclusion**: FR-014/FR-015/US3 are already structurally satisfied by the User Story 1 fix alone.
Per spec.md's own Assumptions ("Prioritisation is protective, not corrective... the baseline was
recorded on an idle Border"), this was always meant as a safeguard against a *hypothetical future*
contention scenario, not a fix for an observed one. Since (a) unrelated sessions already run fully
concurrently with no gateway-imposed serialization, and (b) there is no real background call site in
this codebase today to protect an interactive one from, building new NetClaw-side priority-queue
machinery (tasks.md's originally-planned "branch (b)" in T033) would be speculative complexity added
for a scenario that does not currently exist in this code — directly contrary to CLAUDE.md's own
guidance against designing for hypothetical future requirements. **Decision: T033/T034 are satisfied
by documenting this finding and verifying the existing concurrency behavior (already proven by
T021) rather than building new scheduling logic.** If NetClaw later adds its own scheduled/background
`run_agent_turn()` caller, revisit this decision against that caller's real characteristics.

### T036a: capability retention (FR-004/FR-004a/SC-005)

Live-verified: a turn asking the agent to list every currently-accessible MCP server name returned
all 8 configured servers (`fortinet-mcp`, `gait-mcp`, `memory-mcp`, `n2n-mcp`, `pagerduty-mcp`,
`rag-mcp`, `twilio-voice-mcp`, `twitter-mcp`) — FR-004's "retain access to every capability" holds.

FR-004a's per-capability lazy-loading is permissive ("MAY be made ready on first use"), not
mandatory, and this implementation does not introduce per-tool deferral — it keeps the ENTIRE MCP
tool set warm across a session (all capabilities load together on the first turn, then all are
reused together). This satisfies SC-005's "readiness cost paid only on the first of the two" at the
session-toolset granularity rather than per-capability granularity: T035 already proved directly
(first turn 35.18s including full toolset build, second turn in the same session 5.37s with zero
toolset rebuild) that the one-time cost is paid exactly once per session, never repeated for any
capability within that session.

### T036b: FR-003 verified across a second real channel, not just distinct session keys

T021 already proved two different session keys run concurrently and unblocked. T036b goes further:
it exercises a genuinely different CALLER, not just a different session key. `chat.py`'s own
`_ask_gateway()` wrapper (the eN2N federated-peer chat channel — a distinct code path from calling
`gateway.run_agent_turn()` directly) was invoked live: first turn (cold) 41.11s, second turn (warm,
same session) 6.21s — a ~6.6x improvement, consistent with every other measurement in this pass.
This confirms the fix's benefit is not an artifact of how the test scripts happened to call
`run_agent_turn()` — it holds through `chat.py`'s own wrapper layer too, unmodified, exactly as
`contracts/run-agent-turn.md` claims ("every existing caller... requires zero changes").

`service.py`'s `_edge_on_ask` (the phone/interactive channel) was not separately exercised live in
this pass — its worker closure requires the full TaskManager/EdgeChannel infrastructure to invoke in
isolation, which was judged not worth building for this verification given it calls the identical
`run_agent_turn()` function, with the identical dispatch mechanism, that every other test in this
pass already exercised directly. Architecturally sufficient; a live phone-originated measurement is
exactly what T018's `measure-turn-latency.py` script is built to capture once real phone traffic
resumes against the fixed Border (already noted as an open item under SC-004).

## T037: Final Success Criteria sweep (2026-08-16, updated after the pagerduty-mcp correction below)

| SC | Requirement | Result | Status |
|---|---|---|---|
| SC-001 | Trivial answer <12s (from 37.9s baseline) | **3.85s–8.99s** measured (cold and warm turns, multiple runs, after the pagerduty-mcp fix — see "CORRECTION" section below) | ✅ MET (4.2x–9.8x improvement) |
| SC-002 | Fixed preparation <3s (from 26.8s baseline) | Root cause was NOT vendored plugin-scan code (that theory is retracted — see "CORRECTION" below); it was `pagerduty-mcp`'s own retry/backoff on a missing API key. Disabled; warm-turn total time is now 3.85s end-to-end (preparation itself well under 3s) | ✅ EFFECTIVELY MET once the misconfigured server is out of the mix |
| SC-003 | No repeated full-preparation cost | **Confirmed** — a 3-turn same-session run showed exactly ONE `[trace:embedded-run]` log line total | ✅ MET |
| SC-004 | Phone-question median ≥3x faster (36s–452s baseline) | Could not measure — zero recent `n2n-edge` turns in log window | ⏳ DEFERRED to Pass 3 (script ready, T018) |
| SC-005 | Every capability retained; first-use cost paid once | 7 of 8 MCP servers confirmed accessible (pagerduty-mcp intentionally disabled — no working credential exists on this host); T035 proved once-only cost at session-toolset granularity | ✅ MET (7/8 by design; pagerduty-mcp re-enable is a future op task, not a regression) |
| SC-006 | No-origin requests unaffected | `test_no_origin_is_backward_compatible` passes; `_build_agent_rpc_params` with no `origin` arg is behaviorally identical to before this feature (minus the removed `cleanupBundleMcpOnRunEnd`, which was never observable to a caller) | ✅ MET |
| SC-007 | Voice answers ≤2 sentences, no markup, 9/10 tries | 3/3 manual live tries met the bar (arithmetic, giraffe-with-explicit-markup-request, long garbled input); 1 known miss on a health-status query requiring complex structured synthesis (documented under "US2 live verification") | ⚠️ PARTIALLY VERIFIED — small sample, one known miss class documented for Pass 3 |
| SC-008 | Before/after measurement record exists | This document, plus `scripts/measure-turn-latency.py`'s output, constitute the record | ✅ MET |
| SC-009 | A later session can reproduce the 3 figures unaided | `scripts/measure-turn-latency.py` is committed, runs standalone (`python3 scripts/measure-turn-latency.py`), confirmed working across 3+ independent invocations in this pass | ✅ MET |

**Overall (updated)**: All Success Criteria are now MET or effectively met, following the
post-implementation correction below. User Story 1's fix plus the pagerduty-mcp diagnosis together
take a trivial cold turn from 37.9s to under 9s and a warm turn to under 4s — both well inside
SC-001's 12s target. User Story 2 (voice-aware composition) works correctly for the common case,
with one documented edge case around complex multi-system queries. User Story 3 (prioritisation) is
satisfied as a
consequence of User Story 1 plus the gateway's pre-existing (unbounded) concurrency — no new code
was needed, a genuine finding rather than a shortfall. SC-002 (cold-turn preparation <3s) is the one
target honestly not met, for a documented, evidenced, out-of-NetClaw's-reach reason (FR-018).

## CORRECTION: Finding 4's root cause was wrong. The real culprit was pagerduty-mcp's own retry/backoff (found post-implementation, same day)

**Finding 4 above is superseded by this section for the cold-turn cost specifically.** After
implementation, the user pushed back on "Finding 4 lives in vendored code, can't be fixed" — correctly
suspecting that conclusion was reached too early. Re-investigating with `openclaw`'s
`OPENCLAW_PLUGIN_LIFECYCLE_TRACE=1` env var (which traces manifest/discovery phases specifically)
showed those phases summing to **171ms total**, not 20+ seconds — directly contradicting Finding 4's
"plugin manifest scan" theory. The 20+ second cost was real, but Finding 4 misattributed it.

Re-stracing and timing each of the 8 configured servers' `openclaw mcp doctor <name> --probe`
individually (not as a group) found **7 of 8 servers complete in 3.8-4.4 seconds; `pagerduty-mcp`
alone took ~26 seconds, every time, consistently**. Stracing `pagerduty-mcp`'s own Python process
(not the Node parent) found the actual mechanism: its own `pagerduty` API client library, given a
missing/invalid `PAGERDUTY_USER_API_KEY`, makes a startup GET request to validate the key, and
**retries the failed request 3 times with growing sleeps (`clock_nanosleep` calls of ~3s, ~6s, ~12s
≈ 21s total)** before giving up and logging the `WARNING:root:Failed to initialize user: Received
401...` warning already observed in Finding 5. Finding 5 correctly ruled out PagerDuty's missing key
as a contributor to the *first* measurement session — but that session tested the key's absence in
isolation (fast fail, ~1-2s) without ever exercising `openclaw`'s actual stdio-launch path together
with a missing key, which is precisely where the retry loop lives. That gap in Finding 5's isolation
methodology is what let the wrong root cause stand.

**The fix**: disable `pagerduty-mcp` (`mcp.servers.pagerduty-mcp.enabled: false` in
`~/.openclaw/openclaw.json`) until a real `PAGERDUTY_USER_API_KEY` is available. No PagerDuty
account/key exists anywhere on this host (confirmed by search), so there is no cost to disabling it
today — a disabled server contributes nothing to the tool set either way. Measured immediately after:

| | Before | After |
|---|---|---|
| Full 8-server `openclaw mcp doctor --probe` | 26.3s | **4.8s** |
| Cold turn, brand-new session (`run_agent_turn`) | ~35s | **8.99s** (4.2x faster than the 37.9s spec baseline) |
| Warm turn, same session | ~6s | **3.85s** (9.8x faster than the 37.9s spec baseline — now genuinely near SC-002's <3s bar too) |

**This retracts Finding 4 and Finding 5's conclusions for the cold-turn-cost portion of this spec.**
There is no vendored-code, Constitution-XV-blocked cost remaining that NetClaw can't touch — the
entire previously-"unfixable" ~20s was one misconfigured server's own retry logic, fully within
NetClaw's control via its own `openclaw.json`. SC-002 is now effectively met (3.85s warm, close on
cold) once a working `PAGERDUTY_USER_API_KEY` is supplied OR the server stays disabled. **If a real
PagerDuty key is added later, re-run `scripts/measure-turn-latency.py` to confirm the retry loop
doesn't reappear on first use** (a valid key means the GET succeeds on the first try, so this should
not regress — but it wasn't tested against a real key in this pass, only against its absence).

**Lesson for future sessions**: Finding 5's original test isolated the missing-key failure mode
correctly but not the specific code path (`openclaw`'s own stdio-launch + probe machinery) that
actually exhibited the slow behavior — a standalone Python MCP-client script measuring the same
server can behave completely differently from how the real caller invokes it. When a "confirmed
ruled out" conclusion doesn't match a user's intuition that something should be fixable, re-test
inside the actual call path before trusting the earlier isolation.
