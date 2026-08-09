# Cal

Cal is an open research prototype exploring whether an embodied learner can
discover a stable self–environment boundary, persistent entities, and
controlled language-readable state from unlabeled sensorimotor experience.

![Cal entity-belief replay](docs/experiments/assets/v2_m4_unprivileged_replay_seed500.gif)

> **Research status:** the V2 I1 entity belief graph passed its frozen
> calibration, validation, and holdout. The subsequent L0 V8 language-readout
> experiment did **not** pass its unique holdout: 21 of 24 frozen gates passed,
> while three permanence/control-integrity gates failed. Cal is therefore a
> synthetic research prototype, not a validated general world model.

Start with:

- [current evidence and claim boundaries](RESEARCH_STATUS.md);
- [Cal modality system and language boundary](docs/MODALITY_SYSTEM.md);
- [ten-minute reproduction path](REPRODUCIBILITY.md);
- [data card](DATA_CARD.md);
- [open research roadmap](ROADMAP.md);
- [contribution guide](CONTRIBUTING.md).

The complete milestones, hypotheses, controls, negative results, and
acceptance criteria are in the [V1 research plan](docs/RESEARCH_PLAN.md) and
[V2 research plan](docs/RESEARCH_PLAN_V2.md). The Python namespace is `cal`;
the historical rename and frozen-protocol handling are documented in the
[package migration note](docs/PACKAGE_RENAME.md).

## Quick start

```bash
uv sync --extra dev
uv run pytest
uv run streamlit run streamlit_app.py
```

The dashboard is read-only and displays persisted JSON evidence. To inspect a
static replay without running an experiment, open
[`docs/experiments/assets/v2_i1_v4_replay_seed30000.html`](docs/experiments/assets/v2_i1_v4_replay_seed30000.html).

Code is licensed under Apache-2.0. Project-created reports, result summaries,
and demonstration media are CC BY 4.0; see
[`LICENSE-DATA.md`](LICENSE-DATA.md).

## First experiment: body discovery

The initial agent observes:

- a low-resolution visual frame;
- proprioceptive joint state;
- binary touch signals;
- the action it just executed.

The learner is trained to predict the next observation. Body labels are never
used during representation learning; they are available only to evaluation
probes.

The first comparison contains four conditions:

| Experiment | Available signals |
| --- | --- |
| `baseline` | vision, proprioception, touch, action |
| `no_action` | vision, proprioception, touch |
| `no_touch` | vision, proprioception, action |
| `shuffled_modalities` | all signals with broken temporal alignment |

## Repository layout

```text
cal/
  env/          2D world, body, and sensors
  model/        modality encoders, recurrent state, and predictors
  learning/     training loop and experience replay
  evaluation/   body probes and experiment metrics
experiments/    reproducible experiment configurations
tests/          unit and integration tests
```

## Development order

1. Implement deterministic body dynamics and sensors.
2. Generate and replay random-action trajectories.
3. Train the recurrent multimodal predictor.
4. Freeze it and evaluate body information with a linear probe.
5. Run the three ablation experiments.

## Record a trajectory

Generate 100 learner-facing transitions:

```bash
python -m cal.learning.replay artifacts/trajectory-000.json \
  --steps 100 \
  --seed 0
```

Each transition has the form:

```text
observation(t) + action(t) -> observation(t+1)
```

The JSON file contains vision, proprioception, touch, actions, and the
configuration required for deterministic replay. It deliberately excludes
body masks, object masks, and all other evaluation-only state.

Use a `.jsonl.gz` suffix for the versioned compressed stream format:

```bash
python -m cal.learning.replay artifacts/trajectory-000.jsonl.gz \
  --steps 100 \
  --seed 0
```

`iter_compressed_experiences` validates and yields one transition at a time,
`verify_compressed_trajectory` strictly replays without materializing the
trajectory, and `CompressedTrajectorySequenceIterableDataset` buffers only one
training window.

## Train the first prediction baseline

Create the project environment and run the GRU baseline:

```bash
uv sync --extra dev
uv run cal-train experiments/baseline.yaml \
  --output results/M1-gru-full-seed000
```

The runner records the learned model's validation history together with the
copy-last-observation and mean-observation baselines. Model inputs never
include evaluation masks.

The first measured baseline and its limitations are documented in
[the M1 prediction report](docs/experiments/M1_PREDICTION_BASELINE.md).

Evaluate whether the frozen state linearly exposes the body mask:

```bash
uv run cal-probe \
  results/M1-gru-full-seed000/checkpoint.pt \
  experiments/baseline.yaml \
  --output results/M1-gru-body-probe-seed000
```

The body masks are regenerated only during evaluation by deterministic world
replay. Probe gradients cannot reach the prediction model.

The first frozen-probe results and their limitations are documented in
[the M1 body-probe report](docs/experiments/M1_BODY_PROBE.md).

The first modality and temporal controls are documented in
[the M1 ablation report](docs/experiments/M1_ABLATIONS.md).

Evaluate zero-shot prediction and finite-experience adaptation after body or
sensor changes:

```bash
uv run cal-adapt \
  results/M1-gru-full-seed000/checkpoint.pt \
  experiments/baseline.yaml \
  --output results/M1-body-adaptation-seed000
```

The first adaptation curves and their failure cases are documented in
[the M1 adaptation report](docs/experiments/M1_ADAPTATION.md).

Probe whether frozen state distinguishes self-commanded change from additional
exogenous object motion:

```bash
uv run cal-cause-probe \
  results/M1-gru-full-seed000/checkpoint.pt \
  experiments/baseline.yaml \
  --output results/M1-cause-full-seed000
```

The first causal-readout result, including the chance-level negative finding,
is documented in
[the M1 cause-probe report](docs/experiments/M1_CAUSE_PROBE.md).

Run the recoverable five-seed M1 suite and rebuild its aggregate:

```bash
uv run cal-multiseed --output results/M1-multiseed
uv run cal-m1-summary --output results/M1-stage-summary.json
uv run cal-index --results results
```

The complete acceptance decision is in
[the M1 stage report](docs/experiments/M1_STAGE_REPORT.md). M1 did not pass:
the project has therefore returned to the M1b action-causality mechanism
instead of proceeding to M2. The versioned result/provenance contract is
documented in [the result format](docs/RESULT_FORMAT.md).

The first M1b mechanism screen and its remaining limitations are documented in
[the M1b stage report](docs/experiments/M1B_STAGE_REPORT.md).

The subsequent preregistered M1c–M1v mechanism program is complete. None of
the direct-envelope, spatial-state, global-query, curriculum, competitive-slot,
or complete action-basis candidates passed the frozen envelope gate. The
evidence and stopping decision are in the
[M1 extended stage report](docs/experiments/M1_EXTENDED_STAGE_REPORT.md).
M2 remains intentionally unstarted.

The next research hypothesis is defined in the
[Cal V2 research plan](docs/RESEARCH_PLAN_V2.md). V2 is vision-first,
failure-driven and resource-bounded: it begins with identifiability,
supervised-information-ceiling and causal-sufficiency audits, then permits an
online controllable-entity learner only if those audits pass.

V2-A–C and M1 pass their corrected gates. The reviewed M2 failure
(0.8125 crossing identity retention) was addressed with motion/geometry-aware
probabilistic multi-trajectory association. Its implementation-first frozen
holdout passes with 1.000 identity retention and zero switches. M3 now uses a
normalized categorical posterior over complete body graphs. Its one-shot
frozen holdout preserves the observable 0.5/0.5 symmetry, then reaches
0.999994 mean true-graph probability within at most two steps after symmetry
break. A separate one-shot fresh-data confirmation then revalidates M1–M3
without reading either old holdout: M1 F1 is 0.9995, M2 crossing identity
retention is 0.9792, and M3 true-graph probability is 0.999991. The
simulator visibility mask has since been removed from M4: the unprivileged
variant infers occlusion by shadow-casting over its own sensed occupancy,
maintains probabilistic motion hypotheses with online pause-regularity
learning for occluded objects, and passes its one-shot frozen holdout
(occupancy IoU 0.7504, moving-hidden probability 0.7492, with the
assume-all-visible control failing as required). The chain now authorizes a
reconnection design review toward the original object-permanence M2; see
[the unprivileged M4 report](docs/experiments/V2_M4_UNPRIVILEGED_REPORT.md).
Rebuild development artifacts with:

```bash
uv run cal-v2-identifiability
uv run cal-v2-diagnostic-ceiling
uv run cal-v2-causal-sufficiency
uv run cal-v2-audit-summary
uv run cal-v2-m1
uv run cal-v2-m2
uv run cal-v2-m2-review
uv run cal-v2-m3-hypotheses --split development
uv run cal-v2-m3-review
uv run cal-v2-m1-m3-confirm --split development
uv run cal-v2-m1-m3-confirm-review
uv run cal-v2-m4 --exploratory
uv run cal-v2-m4-unprivileged --split development
uv run cal-v2-stage-summary
uv run cal-index --results results
```

Launch the read-only project dashboard with:

```bash
uv run streamlit run streamlit_app.py
```

The dashboard reads persisted JSON artifacts only. It shows the V2 stage
chain, fresh M1–M3 confirmation, mechanism controls, protocol audit, resource
budget, and per-seed confirmation episodes; it does not rerun experiments or
rewrite frozen protocols.

The next I1 architecture, a unified entity belief graph, subsequently passed
its reviewed calibration, one-shot validation, and one-shot holdout with all
13 gates true. Generate its presentation-only interactive replay with:

```bash
uv run cal-v2-i1-replay --seed 30000
uv run cal-v2-i1-replay --seed 30000 \
  --check docs/experiments/assets/v2_i1_v4_replay_seed30000.html
```

The replay is restricted to repeatable calibration seeds and never consumes
validation or holdout seeds. See the
[I1 final report](docs/experiments/V2_I1_NEXT_ARCHITECTURE_RESULT.md) and
[replay guide](docs/experiments/V2_I1_REPLAY_GUIDE.md).

The next L0 probe freezes I1 and tests whether controlled Chinese propositions
about self, spatial relations, identity after reappearance, and hidden-object
permanence are linearly readable from its entity state. Its shortcut-resistant
V4 development run passes every frozen gate and three final independent
reviews. Its V5 exact-source-lock and one-shot origin registry are implemented;
the only V5 review-holdout attempt was authorized and consumed, but stopped
before producing metrics because its frozen identity-scramble control could not
be constructed from the holdout events. V5 therefore has no passing holdout
claim and cannot be retried. A preregistered V6 row-local counterfactual removes
that structural dependency and passes all 24 development gates on a clean
implementation commit. After review hardening, three independent final reviews
report no P0/P1/P2 findings. Its V7 exact-source lock was published as tag
object `b8b391abc5b54aa7acbf58bef6a6cdf2c7d32664`, targeting
`db524a3d1b65a232c2159541a79d7098227848f5`. Post-lock independent review found
one-shot crash-recovery defects, so V7 remains unopened and unauthorized and
must never be consumed. Those defects are fixed and five rounds of independent
review end at P0=0/P1=0/P2=0. V8 froze the repaired control plane under the
new `calmodel-l0-v8-*` namespace. Its unique holdout was subsequently
authorized and consumed. The formal readout passed its primary self, spatial,
identity, permanence, macro, and per-seed performance gates, but the run ended
with `stop_and_report` because three frozen control gates failed: it did not
beat raw sensors on permanence, the assume-all-visible control did not fail
permanence, and the identity-scramble integrity condition lacked complete
opposite-motion coverage. The exact result is preserved in
[`results/V2-L0-language-readout-holdout-v8.json`](results/V2-L0-language-readout-holdout-v8.json);
see the
[L0 language-readout report](docs/experiments/V2_L0_LANGUAGE_READOUT.md) and
[research status](RESEARCH_STATUS.md).

Generate the repeatable, presentation-only L0 language replay with:

```bash
uv run cal-v2-l0-language-replay --seed 33100
uv run cal-v2-l0-language-replay --seed 33100 \
  --check docs/experiments/assets/v2_l0_language_replay_seed33100.html
```

The page aligns the I1 world/observation/belief views with ten controlled
Chinese propositions and lets the viewer switch between the frozen I1 entity
graph and the raw-sensor control. It accepts only repeatable
development-validation seeds `33100`–`33103`; it rejects every training,
unknown, and V8 holdout seed before simulation. See the
[L0 replay guide](docs/experiments/V2_L0_LANGUAGE_REPLAY_GUIDE.md).

## Randomized-occlusion permanence (development, not frozen)

The V8 failure was diagnosed as an environment problem rather than a model
problem: the old occlusion screen sat at a fixed column with a fixed door and
the hidden object's direction followed seed parity, so a hidden position after
`k` steps was a deterministic function of `(k, seed parity)` and a raw-sensor
linear probe could beat the formal model without any permanence reasoning. The
diagnosis and the proposed replacement are in the
[permanence diagnosis and preregistration draft](docs/experiments/V2_L0_PERMANENCE_DIAGNOSIS_AND_PREREGISTRATION_DRAFT.md),
which is explicitly **not frozen**, and the implemented program is described in
the [stochastic permanence plan](docs/experiments/V2_I1_STOCHASTIC_PERMANENCE_PLAN.md)
and [Phase-R capacity amendment](docs/experiments/V2_I1_PHASE_R_CAPACITY_AMENDMENT_V3.md).

`cal/evaluation/randomized_occlusion_world.py` re-randomizes the occluder
column, extent, door, and extra blockers per episode. Its development-only,
non-gated artifacts are rebuilt with:

```bash
uv run cal-v2-i1-permanence-phase0     # reference health and power design
uv run cal-v2-i1-permanence-phase-r    # kernel capacity conformance
uv run cal-v2-p1-permanence-controls   # V8 control constructability census
```

Both artifacts currently record `phase0_go` / `phase_r_go`. **No candidate has
been run through the confirmatory battery, and nothing here is frozen or
gated.**

The first two commands verify
[`experiments/V2_P1_PERMANENCE_STACK_SOURCE_LOCK_V2.json`](experiments/V2_P1_PERMANENCE_STACK_SOURCE_LOCK_V2.json)
before doing any work and refuse to run if any of the 22 locked permanence
sources has changed, so evidence cannot be produced by edited code. Changing one
of those files requires a new protocol version — carrying an `amendment_record`
and a regeneration of both development artifacts — not an in-place edit.

The third is a non-gated feasibility census, not a scoreboard: it constructs all
five V8 controls (`raw_sensor`, `assume_all_visible`, `time_shuffled`,
`identity_scrambled`, `random_labels`) on the development split and reports how
many events each can be built from. All five construct, but
`identity_scrambled` is only constructible on **2,081 of 12,473** evaluation
samples — it needs two simultaneously hidden tracked objects. That ratio is what
stopped the V5 holdout part-way, and a consumed holdout cannot be retried, so
any future holdout has to be sized against it.

A preregistered review before freezing returned **`block`** on 2026-08-08. It
confirmed the randomization works — position and raw-sensor probes collapse
from V8's 0.875 to about 0.50–0.55, and layouts are unique across all 104
development seeds — but a red-team candidate that performs **no belief
filtering at all** (constant-velocity extrapolation plus a 125-entry error
table) passed all 18 confirmatory gates, so the battery does not yet measure
the mechanism it is meant to test. Two independent code reviews found no
P0/P1 code defects. See the
[review report](docs/review/REVIEW_PERMANENCE_FREEZE_2026_08_08.md) and its
[follow-up](docs/review/REVIEW_PERMANENCE_FREEZE_FOLLOWUP_2026_08_08.md); the
review process itself is defined in [`docs/review/`](docs/review/).

The proposed replacement gates, with the measurements behind them, are in the
[gate redesign draft](docs/experiments/V2_P1_PERMANENCE_GATE_REDESIGN_DRAFT.md).
It is also not frozen: two thresholds remain open, and the redesign must be
executed together with the seed-derivation and floor-gate fixes in a single
regeneration, because all three invalidate the same development artifacts.

The measured evidence, limitations, and M4 decision are documented in the
[V2 audit report](docs/experiments/V2_AUDIT_REPORT.md) and
[V2 stage report](docs/experiments/V2_STAGE_REPORT.md). The one-shot reviews
are documented separately in the
[probabilistic association report](docs/experiments/V2_M2_PROBABILISTIC_ASSOCIATION_REPORT.md)
and the
[complete-body-graph report](docs/experiments/V2_M3_BODY_GRAPH_HYPOTHESIS_REPORT.md),
and the
[fresh M1–M3 confirmation report](docs/experiments/V2_M1_M3_INTEGRATED_CONFIRMATION_REPORT.md).
