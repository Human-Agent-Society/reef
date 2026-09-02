# Paired GEPA quickstart seed 0 (2026-09-01)

This retained result is the reference the Reef GEPA method is validated
against. The official arm is the pinned upstream GEPA quickstart, run
unchanged; it is the target number. The Reef arm beside it was produced by the
pre-method replication driver - upstream `gepa.optimize` owning the search loop
with Reef underneath it as renderer, episode runner, and artifact backend -
which this branch retains in its first commit,
`feat(gepa): reproduce the GEPA AIME quickstart through Reef`, and which the
method under `recipes/gepa/` replaces. Both arms used optimizer seed 0, the
same 45/45/150 AIME split, `gpt-4.1-mini-2025-04-14` for tasks,
`gpt-5-2025-08-07` for reflection, the same seed prompt, and a 150-call search
budget. The 150 held-out examples are the 30 AIME-2025 problems repeated five
times.

This is a one-seed implementation conformance result. It is not a reproduction
of the GEPA paper's larger DSPy `ChainOfThought` experiment or its absolute
benchmark score.

## Result

- The official GEPA arm improved held-out accuracy from 40/150 (26.67%) to
  58/150 (38.67%), a gain of 12 percentage points.
- The replication arm improved from 41/150 (27.33%) to 56/150 (37.33%), a
  gain of 10 percentage points.
- Both arms selected candidate 3 from four candidates after 198 recorded metric
  calls. Official validation improved from 7/45 (15.56%) to 20/45 (44.44%);
  the replication arm's validation improved from 11/45 (24.44%) to 18/45
  (40.00%).
- Before search, the 450-rollout baseline gate measured 22.00% for the direct
  official path and 20.67% through Reef. The predeclared non-inferiority check
  passed with no failed Reef episodes.
- The official arm took 15,371.5 seconds and cost an estimated $5.458627. The
  replication arm took 2,301.3 seconds and cost an estimated $3.642371.

The frozen scores differ by 0.67 percentage points and the selected scores by
1.33 points. Reef therefore reproduced the official quickstart's improvement
pattern closely for seed 0. Seeds 1 and 2 and the multi-node extension were not
run, so this result does not estimate across-seed variance or complete the
four-cell study.

## Baseline provenance

The baseline gate was paid under one Reef commit of the replication branch and
run identity `0ffbc8e3`, then imported into the seed-0 optimization run at a
later commit of that same branch. The intervening change added a
worker-concurrency override without changing the model, dataset, prompt,
request envelope, or sampling settings. Neither commit survives the branch's
squash, so `manifest.json` retains both source hashes and both run identities
as the durable record; the links they carried no longer resolve. The baseline
path used 10-way concurrency and checkpoint batches for both arms; the 32 Reef
and 16 held-out values in its run identity were inactive defaults for
optimization cells. Both seed-0 optimization arms used 128 workers. The
manifest retains the original baseline report hash alongside them.

## Incorrect-response retention fix

The completed official held-out run used upstream `ContainsAnswerEvaluator` on
AIME-2025 rows that omit `additional_context`. Correct responses were retained
normally. For incorrect responses, upstream computed the zero score and then
raised `KeyError` while constructing optional feedback, so the checkpoint kept
the correct zero but lost the response text. This affected 110 frozen and 92
selected zero-score checkpoints; it did not change either aggregate score.

A later commit of the replication branch normalized the optional context
before evaluation and added a regression test; `manifest.json` retains its
hash. The paid run was not repeated, so the known diagnostic limitation
remains part of this retained record. The method's own feedback hook
(`harness/aime.py`) reproduces the same wording with the context treated as
optional throughout, so the failure mode cannot recur.

## Stored artifacts

`manifest.json` records the immutable source, dependency, model, dataset, and
run identities; aggregate outcomes; usage and cost; and hashes for the
aggregate reports committed in this directory. These include the original
baseline result and run identity plus each optimization arm's config, summary,
and compact GEPA run log. Dataset contents, prompts produced during search,
model responses and reasoning, checkpoints, credentials, and local paths are
not committed.
