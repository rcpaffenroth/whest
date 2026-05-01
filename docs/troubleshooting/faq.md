# Frequently Asked Questions

> [← Documentation](../index.md)

## Can I use numpy directly?

All computation must go through flopscope (`import flopscope as flops` and `import flopscope.numpy as fnp`). flopscope wraps numpy with analytical FLOP counting — your score depends on the FLOP cost of your operations, and only flopscope tracks those costs.

## Can I use scipy?

Yes. scipy is not part of flopscope, so you import it separately as your own dependency. Common usage: `scipy.special.ndtr` for the standard normal CDF. Add `scipy` to your `requirements.txt` when packaging.

## Why is my score `inf`?

Either your estimator raised during `predict()`, returned invalid data (wrong shape, NaN, non-numeric), or exhausted the FLOP / wall-time budget. Since 2026-04, explicit predict errors surface through an "Estimator Errors" panel in the report and set exit code `1`; `inf` with exit `0` means budget or time exhaustion rather than a swallowed exception. Run with `--debug` to see the tracebacks:

```bash
whest run --estimator estimator.py --debug
whest run --estimator estimator.py --debug --fail-fast   # halt at first error
```

## Do I need to use the `budget` argument in `predict()`?

The `budget` argument tells you how many FLOPs you are allowed. You can use it to choose between cheap and expensive algorithms (like the combined estimator does), or you can ignore it and always use the same strategy.

flopscope enforces the budget regardless — if your operations exceed it, `BudgetExhaustedError` is raised and your predictions are zeroed.

## Can I precompute things in `setup()`?

Yes. `setup()` runs before any `predict()` calls and is not under a FLOP budget. Use it for one-time preparation that does not depend on the specific MLP (e.g., lookup tables, configuration).

However, `setup()` does have a time limit (`setup_timeout_s`, typically 5 seconds).

## How do I set a time limit on my estimator code?

At the flopscope level, time limits live on `BudgetContext` via
`wall_time_limit_s`:

```python
import flopscope as flops

with flops.BudgetContext(flop_budget=10_000_000, wall_time_limit_s=2.0) as budget:
    ...
```

In WhestBench CLI runs, `--wall-time-limit` sets that same limit for each
`predict()` call.

## What is `untracked_time_limit`?

`untracked_time_limit` is a WhestBench rule, not a `BudgetContext`
parameter. flopscope reports:

- `tracked_time_s`: time spent inside counted flopscope calls
- `untracked_time_s`: total wall time minus tracked time

WhestBench can then zero predictions if `untracked_time_s` exceeds the
configured `--untracked-time-limit`.

## What happens if I exceed the FLOP budget?

flopscope raises `BudgetExhaustedError` before the over-budget operation executes. The framework catches this and zeros all your predictions for that MLP. You will see `budget_exhausted: true` in the per-MLP report.

## How do I inspect budget summaries while debugging?

Use:

- `budget.summary()` for the current explicit `BudgetContext`
- `flops.budget_summary()` for the accumulated process/session view
- `budget.summary_dict(...)` or `flops.budget_summary_dict(...)` for structured data

If you want namespace attribution, pass `by_namespace=True`.

## Is scoring hardware-dependent?

No. flopscope counts FLOPs analytically based on tensor shapes — not wall-clock time. The same estimator produces the same FLOP count on any hardware. You can develop on a laptop and submit for evaluation on a cluster with identical results.

## How many MLP networks are in a full evaluation?

The default evaluation scores your estimator on 10 MLPs (configured by `n_mlps` in `ContestSpec`). Each MLP has the same width and depth but different random weights. Your aggregate score is the mean MSE across all MLPs.

## What if my estimator is fast but inaccurate?

You are ranked by MSE, not by how few FLOPs you use. Using fewer FLOPs than the budget gives no bonus — only accuracy matters (as long as you stay within budget).

## My local score is great but my submission scores 10x worse — why?

Almost always one of three things:

1. **Module-level state survives between predict() calls in-process.** Your Stage 3 (`--runner local`) iteration accidentally caches results between MLPs (lookup tables, RNG state, memoized partials). Stage 4 (`--runner subprocess`) and the grader run each MLP in a fresh process — that state is gone, and your score collapses. **Fix:** move state to instance attributes (`self._...`) populated in `setup()`, or use the `SetupContext.scratch_dir` for cross-call caching that's recomputed deterministically.

2. **Imports that work in-process fail in a clean subprocess.** A relative import, a missing `requirements.txt` entry, or a side-effecting top-level statement. **Fix:** run `uv run whest run --estimator estimator.py --runner subprocess` locally before submitting, and read the "Estimator Errors" panel.

3. **Numerical non-determinism without a seed.** Random MLP generation, Monte-Carlo ground truth, or your estimator's own RNG. **Fix:** add `--seed N` to your local runs to compare apples-to-apples, and avoid time-based seeds in your estimator.

If your Stage 3 and Stage 4 scores agree but the grader still disagrees, suspect Python-version or BLAS-version drift — `uv run whest doctor` will surface the relevant runtime info.

## Next step

- [Common Participant Errors](./common-participant-errors.md)
- [Debugging Checklist](../how-to/debugging-checklist.md)
- [Scoring Model](../concepts/scoring-model.md)
