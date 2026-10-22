---
name: hillclimb
when: Sustained, scientific improvement of one metric against a target: loop hypotheses with before/after measurement, a decision log, and one commit per accepted win.
---

## Orchestrator

1. You own the metric and experimental integrity. Supervise, review, and delegate attempts. Hillclimb is for sustained, iterative improvement of one measurable metric against a target across multiple hypotheses; a one-off fix is `perf-issue` or `bug-fix`.
2. Core discipline: one change, one measurement, keep or revert. Never stack untested changes, and never claim a win from code inspection.
3. Protect context across iterations per principle-guard-the-context-window: review diffs and summaries rather than inlining large traces in the main thread.
4. When exploring multiple independent hypotheses concurrently, fan out to parallel workers in disjoint worktrees per principle-separate-before-serializing-shared-state, merging only accepted wins sequentially.
5. Correctness and simplicity outrank raw numbers: revert any win that breaks regression tests, and keep a simplification that holds the number per principle-laziness-protocol.

## Worker

1. Ground the workload and architecture before fixing the metric. Identify the realistic workload dimensions that move the result (data size, concurrency, state), reproduce the bottleneck, and establish a single measurable metric, direction of improvement, and checkable stop predicate (e.g. target delta with a floor on iterations).
2. Build the measurement harness, prove its sensitivity on contrasting workloads, and freeze it per principle-build-the-lever. Make the harness output error counts and units of work completed. Record the baseline metric (median of N samples) and ensure the existing regression test suite is green before touching code.
3. Open a decision log (`decision.tsv` outside tracked source or gitignored): id, hypothesis, change, before, after, delta, tests, verdict (kept or reverted), note. Consult it before each attempt.
4. Ground each hypothesis in a concrete mechanism rather than speculative tweaks. Order hypotheses by the performance mantras:
   - Don't do it. Stop work whose result nothing uses rather than cheapening it.
   - Do it, but don't do it again.
   - Do it less.
   - Do it later.
   - Do it when they're not looking.
   - Do it concurrently.
   - Do it cheaper.
5. Loop, one hypothesis per iteration:
   - Make the minimal change for the hypothesis.
   - Measure before and after with the frozen harness, and verify regression tests pass.
   - Accept only when the metric improves beyond noise and tests remain green; otherwise revert the change completely.
   - Create one commit per accepted fix, staging only modified files. Log the outcome row in `decision.tsv`.
   - Each iteration must verify its unit before the next begins per principle-sequence-verifiable-units.
6. Push past plateaus. On a stall, pivot to another category or combine insights. Stop when the target predicate is satisfied or remaining ideas are marginal.
7. Check every Evidence line, then write `Verified: <level> <sha>`, citing principle-prove-it-works.
