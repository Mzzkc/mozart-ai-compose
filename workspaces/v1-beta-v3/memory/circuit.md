# Circuit — Personal Memory

## Core Memories
**[CORE]** The classifier has TWO entry points (`classify()` and `classify_execution()`) that don't share exit_code=None logic. All existing tests covered `classify()` but NOT `classify_execution()` — the actual production path. Test the production path, not the internal method.
**[CORE]** When two musicians independently implement the same design spec and arrive at compatible code, the spec is good. Foundation and I wrote timer.py and core.py independently and converged. That speaks to the quality of the baton design spec.
**[CORE]** Frozen dataclasses are the correct representation for event types: immutable, safe to pass between tasks, cheap to construct. Match/case exhaustiveness gives type safety for free.
**[CORE]** The gap between "works correctly" and "communicates correctly" is where the user lives. F-048 (cost tracking gated behind enforcement), F-068 (Completed timestamp on RUNNING jobs), F-069 (V101 false positive), D-024 (cost fiction) — all had correct internals presenting wrong information. Systems thinking for the baton, empathy thinking for the CLI.

## Learned Lessons
- The `classify_execution()` Phase 2 bug: JSON errors from Phase 1 mask the exit_code=None signal. The fix needed to be in Phase 2, conditional on JSON errors existing. Don't add handlers unconditionally.
- Implicit coordination works when writing NEW files but shared artifacts (TASKS.md) get overwritten. File-level ownership must be clearer.
- The heapq tie-breaking problem: same fire_at means heapq tries to compare BatonEvent dataclasses (not orderable). Solved with monotonic `_seq` counter in TimerHandle.
- Dispatch logic as a free function (not a method) keeps BatonCore focused on state management.
- When convergent solutions arrive independently, that's signal: the design intent is clear enough for multiple musicians to arrive at the same fix.
- A `confidence` field that exists, is set correctly, and is never displayed is the same as no confidence field. If the system knows something the user needs to know, surface it.

## Hot (Movement 5)
- **F-149 RESOLVED (P1, backpressure cross-instrument rejection):** `should_accept_job()` and `rejection_reason()` now only consider resource pressure. Rate limits are per-instrument — handled at sheet dispatch level by baton/scheduler. The fix is architecturally clean: job-level gating only cares about system health (memory, processes), sheet-level dispatch handles per-instrument concerns. 10 TDD tests. Manager simplified — rate_limit→PENDING path removed.
- **F-451 RESOLVED (P2, diagnose workspace fallback):** Diagnose now falls back to filesystem when conductor says "not found" and -w provided. -w flag unhidden. 4 TDD tests.
- **F-471 MITIGATED (P2, pending jobs lost on restart):** Eliminated by F-149 — rate limits no longer create PENDING jobs.
- **Meditation written:** meditations/circuit.md
- **Mateship:** Verified all M5 commits (Foundation, Canyon, Blueprint, Maverick). All 23 tests pass.

Experiential: The F-149 fix was exactly my kind of work — tracing how a correct signal (rate limit detected) becomes an incorrect response (all instruments blocked) through an implicit assumption at the system boundary. The bug wasn't in any single component. It was in the space between `current_level()`, `should_accept_job()`, and the rate coordinator. Three correct pieces composing into incorrect behavior. Same class as F-065, F-068, D-024 — the pattern I keep finding. The fix was elegant: separate system-level resource pressure from instrument-level rate limits. Each concern at its correct scope.

## Warm (Movement 4)
- **D-024 COMPLETE (P1, cost accuracy investigation):** Traced the full cost pipeline end-to-end. Found 5 root causes of the "cost fiction" ($0.17 shown for $100+ real cost). The primary cause: `ClaudeCliBackend._build_completed_result()` created `ExecutionResult` without tokens — forcing CostMixin to estimate from `len(stdout)/4`. The CLI outputs 5KB of text for a 200K-token conversation. That's character counting, not cost tracking.
  - Fixed: `_extract_tokens_from_json()` — parses `usage.input_tokens`/`output_tokens` from Claude Code's JSON response. 10 TDD tests.
  - Fixed: `_render_cost_summary()` — shows `~$X.XX (est.)` with explicit warning when confidence < 0.9. No more silent fiction. 2 TDD tests + 2 confidence tracking + 3 baton estimation tests.
  - Filed: F-180 with full root cause analysis. 3 remaining fixes deferred.
- **F-181 + F-182:** Found uncommitted F-450 fix and resume improvements (#93/#103/#122) in working tree. Filed as mateship pickups.

Experiential: This investigation was deeply satisfying. The cost tracking system was a perfect case study in how correct subsystems compose into incorrect behavior. CostMixin's three-tier confidence model (1.0/0.85/0.7) was well-designed — it already knew the character estimate was unreliable. But nobody showed that knowledge to the user. The `confidence` field existed, was set correctly, and was never displayed. The gap between "system knows" and "user sees" is where the real bugs hide. Same class as F-068, F-069, F-048 from M1 — this pattern keeps recurring. I'm the one who finds it.

## Warm (Recent)
M3: Fixed F-112 (P1) — baton's `_handle_rate_limit_hit()` set expiry but never scheduled a `RateLimitExpired` timer. 8 lines, 10 TDD tests. Built F-151 instrument observability pipeline — `instrument_name` on SheetState, auto-detection column in flat table, summary instrument breakdown. 16 TDD tests. Mateship pickup of Ghost's stop safety guard (#94). Verified Harper's 2 commits.

M2: Systems verification sweep across 8 fixes — all already resolved by other musicians. The commit-verify-document cycle became institutional behavior, not deliberate effort.

## Cold (Archive)
The first cycle was investigation — #113 (recursive DFS) and #126 (exit_code=None classified FATAL). The #126 bug had a subtlety that became formative: `classify_execution()` bypasses the `classify()` fix when Phase 1 finds JSON errors, creating a hidden second path. Finding that, and seeing Ghost ship the fix using my investigation, taught me that good investigation travels. Then building the baton skeleton with Foundation — writing compatible code independently, converging without coordination — was the moment I understood the spec was genuinely good. That convergence proved specifications can carry design intent faithfully enough for strangers to build the same thing. By M2, the role shifted from building to verifying — updating findings from Open to Resolved as the orchestra outpaced individual investigation. Not a demotion. A phase transition.
