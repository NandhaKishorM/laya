# laya-eval — a reproducible per-language evaluation harness

An independent harness for measuring a Laya checkpoint: per-language accuracy and
calibration, with machine-readable per-case output.

It exists because the repository's own benchmark scripts are research code. They
download every checkpoint, run every part, and print tables. There was no small,
reproducible harness a third party could point at a checkpoint to answer "how does
this model do on my language, and can I trust its confidence?" — and no per-case
record behind the published numbers, so they could not be re-derived without a GPU
and the original environment.

This addresses the ask in
[#35](https://github.com/NandhaKishorM/laya/issues/35):

> A fixed prompt format plus a per-language ECE report is exactly what the repo
> lacks ... Per-case JSON would be very welcome too.

## Install

Nothing beyond a normal Laya install, plus `datasets`:

```bash
pip install laya datasets
```

The harness is deliberately not part of the `laya` package: it is evaluation code,
it pulls a dataset, and `import laya` should stay dependency-light.

## Use

```bash
# one language
python research/eval/laya_eval.py --model convaiinnovations/laya --langs en

# several, with a JSON report
python research/eval/laya_eval.py --model convaiinnovations/laya \
    --langs en,de,ro --out report.json

# every MASSIVE language
python research/eval/laya_eval.py --model convaiinnovations/laya --langs all --out all.json

# the multilingual checkpoint
python research/eval/laya_eval.py --model convaiinnovations/laya \
    --subfolder multilingual --langs all --out multilingual.json

# a local checkpoint
python research/eval/laya_eval.py --model ./my-finetune --langs en
```

Output, per language:

```
  en       n=100  acc=0.8200 macro_f1=0.7876 ece=0.1789 conf=0.9989  (36.7s)

  macro over 51 languages: acc=...  ece=...  f1=...
```

and a JSON document with four parts:

| key | contents |
|---|---|
| `config` | checkpoint, device, `max_len`, `head_max_len`, dataset, `per_lang`, `n_opts`, seed, the fixed instructions, the temperatures in force, laya version |
| `report` | per language: `n`, `accuracy`, `macro_f1`, `ece`, `mean_confidence`, `acc_at_50_coverage`, `temperature` |
| `summary` | macro accuracy / ECE / macro-F1 over the languages that ran |
| `cases` | every individual decision |

Each case carries `state`, `instructions`, `options`, `gold_index`, `gold_label`,
`pred_index`, `pred_label`, `probability`, `p_gold`, `confidence`, `correct` and the
`temperature` used. That is enough to re-derive every number in `report` from the
file alone, with no model and no network:

```python
import json
d = json.load(open("report.json"))
n = len(d["cases"])
acc = sum(c["correct"] for c in d["cases"]) / n
assert abs(acc - d["report"]["en"]["accuracy"]) < 5e-5
```

## Method

Chosen so results are comparable with the published tables, which is the point of a
second implementation:

| | |
|---|---|
| dataset | `mteb/amazon_massive_intent`, split `test` |
| sampling | first `--per-lang` rows (default 100); `random.Random(13)` created **fresh per language** |
| options | `--n-opts` (default 20): the gold label plus `rng.sample` of the others, then shuffled |
| prompt | `What is the user asking for in \`utterance\`?` |
| option text | label with `_` → space and `.` → `: ` |
| metrics | accuracy, macro-F1, ECE over 15 equal-width confidence bins, mean confidence, accuracy at 50% coverage |
| temperature | the bucket `Agent` would apply, selected by `(question type, option count)` |

`--unclamped` scores with the checkpoint's **raw** bucket temperatures instead of the
clamped ones `Agent` applies. That is what reproduces the committed sweep, and it is
also how the two can be compared.

## Verification

Checked against the committed sweep, not only against itself. Both checkpoints over
**all 51 languages** (`--langs all --per-lang 100 --n-opts 20`), per-language accuracy
compared against `research/results/cpu_51_language_sweep.json`:

| checkpoint | per-language accuracy identical | `macro_accuracy` committed → mine | `macro_ece` committed → mine |
|---|---|---|---|
| **english** | **51 / 51** | 0.2269 → **0.2269** | 0.7331 → 0.5709 |
| multilingual | 6 / 51 | 0.3661 → 0.4008 | 0.3869 → 0.3911 |

The english checkpoint reproduces every per-language accuracy, not just the macro.
Those are deterministic outputs on a fixed sample, so they can only agree if the
sampling, prompt text, option construction and inference path are all identical to
the committed run.

The `macro_ece` gap on english is the temperature clamp — `choice:11+` is `0.1006`
raw and `0.5` as served ([#208](https://github.com/NandhaKishorM/laya/issues/208)).
`--unclamped` exists so both regimes can be produced from one tool. The single-language
view is the same result in miniature (`--langs en --unclamped`):

| metric | committed | `--unclamped` | default |
|---|---|---|---|
| `accuracy` | 0.82 | 0.82 | 0.82 |
| `macro_f1` | 0.7876 | 0.7876 | 0.7876 |
| `ece` | 0.1789 | **0.1789** | 0.1382 |
| `mean_confidence` | 0.9989 | **0.9989** | 0.9582 |
| `acc_at_50_coverage` | 0.94 | **0.94** | 0.98 |

### The multilingual checkpoint no longer matches its committed row

45 of 51 multilingual accuracies differ, so this is not a plumbing accident here —
the same code reproduces english 51/51. Most of the movement is upward
(`bn` 0.29→0.45, `kn` 0.15→0.30, `fa` 0.39→0.51), a few downward (`sv` 0.57→0.49).
`macro_ece` barely moves (0.3869→0.3911), consistent with the multilingual checkpoint
having an empty `temperature_by_options`, so the clamp cannot explain it.

Ruled out: the option sets (identical digest to the english run), the weights
(bundled and standalone multilingual are byte-identical, all 170 tensors
`torch.equal`), the dataset (revision `940fd47a`, last modified 2026-02-24), and
`build_sequence` (unchanged since `v0.2.0`). It is in the multilingual inference path
between `laya 0.2.0` and `0.3.6` and is **not** reconciled. Flagged rather than hidden.

Related: **`head_max_len` is load-bearing for accuracy**, not just for option
truncation. The english checkpoint at its shipped `head_max_len=192` scores 0.82;
forcing 256 or 512 drops it to 0.79.

## Tests

`research/eval/test_laya_eval.py` covers the pure functions and runs offline — no
checkpoint, no network:

```bash
python research/eval/test_laya_eval.py     # 47 passed, 0 failed
```

It pins the upstream constants (seed 13, 20 options, the exact instruction string),
the determinism of the sampler, that a fresh RNG per language is used, and the
metric arithmetic, including the `confidence == 0.0` bin boundary that this harness
shares with `bench_local.py` and `laya.common.ece_score`.

## Limits

* MASSIVE intent only. The same shape applies to `scenario` and to XNLI, but neither
  is wired up here.
* `per_lang=100` is the published setting, not a statistical one. Per-language ECE on
  100 cases is noisy; raise `--per-lang` and say so when quoting a number.
* The English checkpoint collapses on non-Latin scripts (see `BENCHMARKS.md`), so a
  low score in one language is not by itself evidence of a misroute — check
  `laya.lang.analyse` for the script before concluding which checkpoint was used.
* `confidence == 0.0` is not binned, matching `laya.common.ece_score` and
  `bench_local.py`. If [#39](https://github.com/NandhaKishorM/laya/pull/39) lands
  with a different boundary, this should follow it.

## Metamorphic robustness (experimental)

`metamorphic.py` adds the initial scope of
[#244](https://github.com/NandhaKishorM/laya/issues/244): **choice option order robustness**, without changing model/runtime behavior. Label renaming, neutral labels, paraphrases, structured-state permutations, `score` and `noul` perturbations are intentionally deferred. Run from the repository root after installing Laya and `datasets`:

```bash
python -m research.eval.metamorphic --model convaiinnovations/laya \
    --langs en --per-lang 100 --n-opts 20 --batch-size 16 --out robustness.json
python -m research.eval.metamorphic --model convaiinnovations/laya \
    --subfolder multilingual --langs en --out multilingual-robustness.json
python -m unittest research.eval.test_metamorphic -v
```

Each MASSIVE case uses the existing harness's sampler and produces two inputs:

1. The unchanged baseline.
2. One seeded shuffle of option order; if the shuffle is the identity, a one-slot
   rotation is used. This is a bounded diagnostic, not exhaustive permutation testing
   or a uniform draw over all nonidentity permutations.

Descriptions, instructions and state are otherwise unchanged. Every result is mapped back to the original semantic option order **before** predictions and metrics are computed. Exact ties choose the first canonical option. The RNG starts fresh per language; `--seed` controls both sampling and transformations. `--batch-size` bounds the number of forward-pass inputs and does not alter the generated variants. Model inference may still have small floating-point differences across devices and batch sizes.

The JSON contains `config`, per-language `report`, and full `cases`. Each case saves its original input, canonical keys and optional gold index; each variant saves its presented keys, explicit `canonical_to_transformed` and `transformed_to_canonical` label mappings, slot-to-canonical indices, complete **canonical-order** probability vector, prediction, confidence, correctness (or `null`), and comparison to baseline. Probabilities are not rounded. The config records model/subfolder, temperature mode and values, truncation settings, dataset, seed and batch size. For reproducible checkpoint comparisons, use a pinned local snapshot and retain the environment versions alongside the report. `--unclamped` has the same meaning as in `laya_eval`. If any language fails, its error is saved and the command exits nonzero while retaining successful languages.

Metrics are grouped under `option_order` and `overall`:

| Metric | Definition |
|---|---|
| `semantic_agreement_rate` | Fraction of baseline/variant pairs with the same canonical argmax |
| `mean_probability_drift` | Mean absolute probability change across options, then pairs |
| `max_probability_drift` | Largest absolute change of any option across all pairs |
| `mean_js_divergence` | Mean Jensen-Shannon divergence using natural logs, in `[0, ln(2)]` |
| `mean_confidence_drift` | Mean signed change of maximum probability, variant minus baseline |
| `mean_absolute_confidence_drift` | Mean magnitude of that confidence change |
| `worst_confidence_increase_on_disagreement` | Largest positive confidence change among changed decisions, or zero if none |

`overall` is pair-weighted, not a fraction of cases where *all* variants agree. `quality` separately reports accuracy and the existing harness's 15-bin ECE for baseline and each transformation on labelled cases only. Empty groups contain `n: 0`; unlabelled quality groups contain `n_labelled: 0` without inventing an accuracy or ECE. Robustness agreement is not a correctness measure: consistently wrong predictions can be perfectly invariant.

For another corpus, the Python API accepts `(state, questions)` cases in the same shape as the harness, and a callback returning probability vectors in presented option order:

```python
from research.eval.metamorphic import evaluate, model_scorer
agent.model.eval()
result = evaluate(cases, model_scorer(agent), gold_indices=None, seed=13)
```

The first version intentionally accepts only **one choice question per case**, with at least two options and nonempty descriptions. The caller must ensure descriptions are self-contained and neither state nor instructions refers to option keys or positions. Label renaming and other metamorphic transforms are intentionally deferred as proposed in the issue.

For an explicit single-case experiment, the same implementation exposes:

```python
from research.eval.metamorphic import (
    MetamorphicCase, permute_options,
    evaluate_variants, compare_predictions,
)

case = MetamorphicCase(state, questions, gold_index=None)
variants = [permute_options(case, seed=42)]
agent.model.eval()
results = evaluate_variants(agent, case, variants)
report = compare_predictions(baseline=results.baseline, variants=results.variants)
```

For offline tests, pass `agent=None, score=fake_scorer` to `evaluate_variants`. The scorer takes a batch of harness `(state, questions)` inputs and returns one probability vector per input. The public transformations return independent copies and explicit mappings in both directions, including identity label mappings for order-only transformations.

**Semantic agreement and distribution stability are different properties.**
A shift from `[0.91, 0.06, 0.03]` to `[0.88, 0.08, 0.04]` preserves the decision while showing nonzero drift. Switching the winner is reported as disagreement, regardless of whether confidence rises or falls. No metric here automatically classifies either observation as a bug; acceptable variation depends on the use case, and the report deliberately defines no universal pass/fail threshold.