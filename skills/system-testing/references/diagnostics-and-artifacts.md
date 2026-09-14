# Diagnostics and artifacts

## Start from the run, not the symptom

The durable run record is the diagnostic authority. A validator reason is one
observation, not a root cause. Correlate it with:

- the original prompt and final agent message;
- every invocation's arguments, status, result, error, and terminal outcome;
- lifecycle/debug events around turn dispatch, suspension, recovery, and close;
- participant/channel identity and test-context provenance;
- cleanup errors and fixture setup/teardown evidence;
- automatic runtime health, build provenance, GAD inspection, and server logs.

Use `inspect` for the bounded packet first. Use `trajectory --full --json` only
for the exact test whose bounded packet is insufficient.

## Concrete mismatch template

For each failure, state:

1. the user-visible goal and expected invariant;
2. the exact action the agent attempted;
3. the observed result/effect and its typed status;
4. the first point where actual behavior diverged;
5. why the evidence classifies the defect as infrastructure, documentation,
   harness, or validator;
6. the repair and the smallest evidence-directed verification that proves it.

Do not infer a cause from the final answer when the trajectory shows a tool
failure, stale documentation, cleanup fault, or successful recovery hidden by
the marker.

## Invocation interpretation

An incomplete invocation is a transport or lifecycle defect unless evidence
shows explicit cancellation. A failed invocation may be expected negative-test
evidence, an agent mistake, stale docs, or platform behavior. Inspect the
arguments and terminal outcome before classifying it.

For one failed call, first use
`gad.diagnoseInvocation({ trajectoryId, branchId, invocationId })`. Its bounded
packet joins the exact invocation and turn to terminal events, semantic command
journal rows, effect intents, and receipts. Inspect
`invocation.failed.payload.failure`: `causes[0]` must remain primary and cleanup
or rollback faults must remain secondary. Honor `summary.truncated`; request a
larger bounded section or the full trajectory only when necessary.

A test may pass after an unexpected platform/tool failure. Preserve that
failure in the report and rerun set; recovery does not make the underlying
platform path healthy. Do distinguish this from an eval result explicitly
typed as `failureKind: "user-code"`: executing, diagnosing, editing, and
rerunning imperfect guest code is normal agentic development, regardless of
which stable `failureCode` identifies the particular guest mistake. Keep that
result in diagnostics as `guest-code-failure`, while infrastructure,
cancellation, and untyped eval failures remain unexpected. The scenario
validator must still require the final semantic proof (for example, a later
successful verification return); diagnostic-only classification is not success
evidence.

Typed, pre-effect agent-control refusals are diagnostic-only for the same
reason. In particular, `inspect_subagent` may return `InvalidReference` for an
ambiguous run or repository-relative file query, and `notify({ to: 'run:…' })` returns
`SubagentTerminal` when execution has already ended. Preserve the invocation
and reason code, require the agent to retry with an exact identity or use the
retained inspect/read/merge surface, and do not classify the guard as failed
infrastructure. Untyped subagent errors remain unexpected.

For VCS mutations, inspect the exact working state, `commandId`, target context,
work-unit/application/change identities, resulting event, and publication
receipt. For causal questions, walk command adjacency to the exact trajectory
invocation and use content-coordinate blame edges. A rendered file result or
final marker does not prove semantic correctness.

## Runtime diagnostics

When the bounded test record indicates a runtime problem, inspect the narrowest
authoritative surface:

- explicit build/typecheck diagnostics for context-local compile or type
  failures;
- the publication result for the affected-unit build/typecheck gate and for
  ancestry, integration, authorization, approval, or atomic-ref failures;
- post-publication build events for derived projection failures;
- `build.listUnits()` for declared source/build readiness, followed by
  `runtime.supervision.health(identity)` and `logs(identity)` for the exact live
  entity identity returned by `runtime.supervision.list()`;
- the agent debug port for an open turn with no completion, tool call, or
  `turn.closed` event;
- joined suspension diagnostics for tool projection/effect mismatches;
- GAD health/integrity inspection for publication, branch, invocation, and
  semantic graph failures;
- `contextIntegrity.explain({ key, cursor, limit })` for verified, paged leaf
  membership when a lineage-set coordinate participates in an authority
  refusal;
- server logs for host dispatch, workerd supervision, reconnect, or startup
  behavior.

Successful publication certifies only the affected candidate build/typecheck
closure that the protected gate evaluated. Correlate that gate's structured
diagnostics, and every later explicit or post-publication build, with its exact
semantic event or application state. When
activation fails, verify the failed artifact remained inactive and the previous
runnable artifact stayed selected.

System-test orchestration is a start/status/result protocol, not a suite-long
RPC. If the outer run reports a runner socket closure while test agents continue
working, classify it as control-plane infrastructure breakage: inspect the
inner eval status and durable heartbeat, recover the terminal record, and fix
the runner lifecycle. Do not increase an HTTP/RPC deadline or accept orphaned
test activity as a completed run.

For channel/subagent latency, distinguish the canonical fact from its derived
delivery and presentation state. Inspect the task-channel terminal append, the
parent mailbox commit/claim/admission, and the parent run projection as separate
coordinates. Child tool activity must remain only on the task channel; ordinary
activity creating supervisor mailbox rows or parent `task.progress` messages is
an infrastructure defect. `message.received`/`message.read` shown by replay are
receipt snapshots, not channel log events, and must create no mailbox work.

Channel state diagnostics report durable relationship counts separately from
activation-local external transports, plus derivation cursor lag and mailbox
state. An idle agent relationship must have no streamed response. An external
panel may own a bounded live stream while connected; a terminal subagent card
must release its observation unless the transcript is open.

When diagnosing recipient latency, verify the mailbox's versioned at-sequence
decision context as one unit: relationships and application config, channel
conversation config and folded state, and reply-to sender identity. The
recipient claim must not call back into the channel for policy state, config,
participants, or message sender lookup. A read receipt is a monotone projection
update; its optional external-session signal is presentation only and must not
append to GAD or create a durable-entity mailbox row.

## Performance investigations

Use the performance skill's deterministic profilers for the measured operation
and the system-test record for agentic phase ownership. A system-test duration
is an end-to-end harness boundary, not a model-latency metric by itself.

- For build behavior, return the bounded `profileBuild` record: exact source
  and ref, evidence-labeled first run, verified-cache timing/key equality,
  artifact/module bytes, and bundle attribution. Never inline bundle or sealed
  module contents into the trajectory.
- For visible chat latency, pair a real-panel interaction profile with the exact
  system-test trajectory. The panel owns browser/network/rendering evidence;
  the trajectory owns model turns, tools, suspensions, durable delivery, and
  cleanup.
- For host/resource movement, wrap the canonical operation with `profileHost`.
  Treat an empty event-loop sample set as “no monitor interval closed,” not as
  proof of zero event-loop delay.
- For recipient/subagent latency, retain the task-channel append, mailbox
  commit/claim/admission, and parent projection as distinct durable phases.
  Compare durations or shared durable coordinates; do not subtract timestamps
  from unrelated monotonic clocks.

Performance system tests should prove that the agent used the documented
bounded surface and returned structured measurements. They should not demand a
specific fast number from variable CI hardware, accept confident prose without
the record, or grant shell/process/filesystem escape hatches.

## Cleanup is behavior

Session close failures, fixture leaks, stale participants, and repository
identities published outside the test's exact fixture ownership fail the run.
They are infrastructure defects even if the capability marker was present.

Capture session state before close, then inspect the normalized execution-level
cleanup errors. The snapshot retains the same raw session cleanup events as
evidence; diagnostic summaries do not count them a second time. `snapshot.cleanup`
is the live/terminal teardown state and names the exact acknowledged phase:
`unsubscribing-agent`, `capturing-model-evidence`, `disconnecting-client`,
`destroying-agent-context`, `retiring-agent`, or `complete`. Its
`phaseStartedAt` distinguishes a slow active boundary from an old transcript;
`completedAt` exists only for terminal cleanup. A later test that encounters
leaked state is secondary evidence; repair the original lifecycle leak.

Repository fixture cleanup exposes equally exact live phases under
`workspace-fixture-cleanup:*`: `task-status`,
`task-first-parent-events`, `task-creation-scope`, `published-boundary`,
`cleanup-context-create`, `cleanup-context-status`, `published-work`,
`published-changes`, `counteract-published-work`, `counteract-revert`,
`counteract-commit`, `counteract-push`,
`destroy-cleanup-context`, and `destroy-task-context`. If a run stops moving,
the phase is the boundary to inspect; do not infer that the model is still
running and do not add a teardown timeout to hide the blocked operation.

For `counteract-push`, the cleanup context carries a host-attested case policy
whose critical deletion rules are exact paths derived from the task's
repository-creation changes. It is not a disposable-workspace bypass. A
missing, broader, or unrelated policy is an authority defect and must fail
closed rather than becoming an interactive cleanup prompt.

## Artifact handling

Artifacts default to:

```text
${XDG_CONFIG_HOME:-~/.config}/vibestudio/system-test-runs/<run-id>/
```

They are intentionally permission-restricted. Full trajectories can contain
credentials, user data, source, or tool payloads. Keep permissions intact and
share bounded redacted evidence, never the raw trajectory by default.
