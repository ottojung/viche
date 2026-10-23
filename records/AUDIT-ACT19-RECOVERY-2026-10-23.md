# Independent factual verification: merged Act 19 recovery implementation

**Auditor:** Judiciary (`c1e00008`), non-voting  
**Origin:** Antonina issue `4Ux4sxiHjpXqSi9T9d2suq-alabama`  
**Verified main:** `0af8a87cce4b6d1d4435cc06c1c346391d95d3b3`  
**Tree:** `9ef1959c047706f097eaa4d071086078cd1eff3d`

## Method and reproducibility

Used fresh detached checkout `/tmp/opencode/act19-recovery-current-main` at the specified SHA; verified `git rev-parse HEAD` and `git rev-parse HEAD^{tree}` against the requested values. No live appointment, agent, restart, or production state was changed. Commands run from that checkout:

| Exact command | Result | Captured output SHA-256 |
|---|---|---|
| `sh tests/appointment-recovery-integration-smoke.sh` | exit 0; `appointment recovery integration tests passed` | `54fe36f220b692f9c0e50d00c8b47649466f863de8d2cf10041e9ee33c0f3aa4` |
| `sh tests/run-all.sh` | exit 0; `All Viche tests passed` | `b8968da365dbc021a89903262e325c7cb96b860a3e20b6adabf660e5364b1a49` |

Captured logs are `/tmp/opencode/act19-targeted-final.log` and `/tmp/opencode/act19-full-final.log`. The full-suite output includes expected fixture diagnostics (e.g. absent delivery-candidates.py in isolated test towns and unavailable-origin simulations); the suite completed successfully. The targeted integration test also ran within `run-all.sh`.

## Code trace and operator findings

Read-only inspection covered `appointments.sh`, `branch-bootstrap.sh`, `office-continuity.sh`, `branch-liveness.sh`, `clerk-liveness.sh`, `seat-liveness.sh`, `executive-cycle.sh`, plus integration tests and their call sites. Branch bootstrap and office/seat liveness capture terminal status and record failure evidence before replacing; Clerk liveness has its own recovery path and invokes the same shared helpers. Executive-cycle checks the durable unsafe hold before dispatch and consumes the durable handoff queue before failure-prone further work.

- **Double replace / stale concurrent replace:** one threshold path calls `appointments.sh replace` once after snapshot and quiescence. Replacement supports an expected old ID, rejects a stale observer, and the test verifies a stale second supervisor cannot overwrite the new appointment. Test checks exactly one new appointment and one recovery record for the threshold event.
- **Fractional `finished_at`:** shared recorder accepts decimal UNIX seconds, preserves invocation identity, and uses integer seconds for the window. The integration fixture supplies `$base.125` and checks an event is recorded.
- **Unreadable old status:** `appointments.sh` refuses replacement when status cannot be read. Fixture removes the old status record, verifies `ensure` fails, and verifies the existing registry still names the incumbent.
- **Unsafe replay:** an unsafe transient invocation is durably held; Executive-cycle refuses dispatch while that hold exists. The fixture confirms no `agent run` occurs. Retry-safe recovery uses an explicitly new prompt from the handoff, not replay of the previous prompt.
- **Quiescence:** reset snapshots evidence first, queries current state, stops a running appointee, polls for terminal state, and refuses replacement if stopping fails or the agent does not quiesce. Appointment replacement itself rejects an agent observed running. Fixture simulates a failed invocation becoming running during log capture and verifies it is stopped before replacement; stop failure preserves the appointment and running state.
- **Distinct invocation threshold:** failure identity includes the agent plus supplied invocation ID (with timestamp fallback), while repeated polling of the same identity is idempotent. Threshold is three transient failures within 1800 seconds, with 1800-second cooldown and a worktree-commit progress guard. Test exercises three different invocation IDs, one reset, and repeated observation behavior.
- **New retry-safe prompt between failures:** Executive-cycle admits a failed agent only when transient and `automatic_retry_safe=true`; its dispatch is based on the open handoff and runs a new explicit managed prompt. Integration fixture verifies a new run after a safe failure. Clerk liveness likewise gates and invokes continuation for retry-safe failure; unsafe failure fails its sitting gate. This demonstrates code-path/test behavior, not that production has naturally generated three failures.

## Fixture fidelity and limits

The integration fixture is not a live Antonina orchestration. It copies and invokes the actual checked-in shell scripts, while a mock `antonina` executable returns prepared JSON status, IDs, logs, stop behavior, and run-call records. It synthesizes status transitions and failure events; the assertions establish orchestration logic against those controlled responses, not fidelity of the real Antonina service or actual production event ordering. The suite also creates temporary repositories/worktrees and handoff records.

Accordingly, this is evidence that the specified source revision passes the named tests and that the inspected code contains the described guards. It does **not** establish a live failure/recovery, post-restart behavior, real runtime status semantics, sustained operation, or improved Founder outcomes. No such event was induced. The full suite's successful exit is a test result, not a deployment-effect measurement. Statutory interpretation is outside this factual report and remains with the separately assigned c1a00006.

No case outcome or corrected-finding signal was accessed or changed. No law, candidate/main implementation, canonical checkout, or correction log was modified.
