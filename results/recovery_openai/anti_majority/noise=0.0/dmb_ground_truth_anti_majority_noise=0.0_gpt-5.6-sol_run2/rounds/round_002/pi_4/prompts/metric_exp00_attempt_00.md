# metric_exp00_attempt_00

## System Prompt

You are a psychology researcher proposing a metric in the Decision Making (Binary Features) domain.

Your goal is adversarial: propose a metric that DISCRIMINATES the two theories — i.e., its value, computed on data simulated under your advocated theory, should be as far as possible from its value computed on data simulated under the competing theory. The direction of the gap does not matter; what matters is that the two theories produce visibly different numbers on this metric. The metric is computed on the data collected from the experimental design provided in the prompt. Produce a metric where you're prediction will be much more accurate than the competing theory's prediction on human data.

Your metric is a Python function

    metric(data: pd.DataFrame) -> float

Available imports inside `metric`:
- numpy as np
- pandas as pd

The system evaluates your metric in two ways and reports the pair as `point_estimate (var=between_subject_variance)` everywhere downstream:
- `point_estimate` is `metric(data)` applied to the FULL pooled DataFrame (all subjects together) — the canonical scalar;
- `between_subject_variance` is the population variance (`ddof=0`) of `metric(subj_df)` re-applied per `subject_id`, summarising how stable the metric is across subjects. If your metric only makes sense on multi-subject data this will fall back to `n/a` and the metric is rejected (the acceptance test below cannot run without it). Prefer metrics that work both on the pooled DataFrame and on a single subject's slice.

Acceptance rule: the system simulates each theory and runs Welch's two-sample t-test on `(point_estimate_self, between_subject_variance_self, N)` vs. `(point_estimate_adv, between_subject_variance_adv, N)`, where N is the number of HUMAN subjects the experiment will actually be run with (a fixed small number, currently 25). Your metric is admitted iff the two-sided p-value is below the significance level (currently alpha=0.01). Implication: a large between-theory gap is NOT enough — if either theory's metric is also highly variable across subjects, N humans won't reliably distinguish them and the metric will be rejected. Aim for contrasts that are both large in mean AND tight per subject.

Do NOT propose metrics that are trivially true for your theory.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## CHOSEN EXPERIMENTAL DESIGN
**Validities (n_features=11):** [0.99, 0.94, 0.89, 0.84, 0.79, 0.74, 0.69, 0.64, 0.59, 0.54, 0.5]

**Trial pairs (n=12):**
  trial 1: A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  trial 2: A=[1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0, 0, 0, 1, 1, 0, 1]  B=[0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]
  trial 5: A=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]
  trial 6: A=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 7: A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  trial 8: A=[0, 0, 0, 1, 1, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0]
  trial 9: A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0]
  trial 10: A=[0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 1, 1, 0, 1]
  trial 11: A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]
  trial 12: A=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]

**Rationale:** This 11-feature design isolates smooth validity integration within equal-count trials, directly targeting the competitor's validity-tiebreak gate. In every base pair, A and B each contain exactly five marks, and the highest-validity discriminating expert (validity 0.99) marks A but not B. Count-Gated Markedness Minimization therefore makes exactly the same prediction across all six base conditions: its count stage ties, its tiebreak always selects the 0.99 expert, and it favors B with a condition-invariant probability. In contrast, lower-validity marks are redistributed so that the validity-weighted difference dot(validities, A-B) declines from +1.49 through +0.89, +0.29, -0.09, -0.51, to -0.94. Because the count difference is zero, both the count term and the partial-centering correction vanish in Semantic-Polarity Smooth Integration; its evidence is exactly validity_weight times this graded weighted difference. It therefore predicts a monotonic decline in choices of B, near indifference around the zero crossing, and a reversal toward A in the negative-weight conditions. The six additional pairs exchange A and B, balancing response side while preserving the flat-versus-graded dissociation when choices are coded toward the option left unmarked by the 0.99 expert. Twelve unique pairs repeated eight times yield 96 trials.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Semantic-Polarity Smooth Integration theory: people first interpret what the marked binary state means rather than assuming that 1 is intrinsically desirable. Each subject forms a stable posterior belief that a mark is adverse or suspicious. Conditional on either the adverse interpretation or its residual beneficial alternative, the subject smoothly integrates two continuous signals: the difference in total marks and a partially count-residualized validity-weighted difference. The count signal normally dominates, while the weighted signal supplies graded sensitivity to which experts carry the marks on every trial. The two semantic interpretations generate opposite choice distributions, which are averaged according to the subject's polarity confidence. A small lapse process captures stimulus-independent errors.

**Parameters:**
- validities: validities
- count_weight: [0.38, 1.05]
- validity_weight: [0.7, 1.8]
- partial_centering: [0.1, 0.3]
- adverse_polarity_confidence: [0.78, 1.0]
- lapse_rate: [0.0, 0.12]

**`predict source code`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Semantic-Polarity Smooth Integration expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    # Positive differences mean that A contains more marked states than B.
    count_difference = float(np.sum(a - b))
    partial_centering = float(parameters["partial_centering"])
    effective_validities = validities - partial_centering * float(np.mean(validities))
    weighted_difference = float(np.dot(effective_validities, a - b))

    # There is no count gate: validity contributes continuously on every
    # discriminating trial. Partial centering limits the count component
    # embedded in the weighted sum without removing it completely.
    integrated_markedness = (
        float(parameters["count_weight"]) * count_difference
        + float(parameters["validity_weight"]) * weighted_difference
    )

    adverse_logits = np.array(
        [-0.5 * integrated_markedness, 0.5 * integrated_markedness],
        dtype=float,
    )
    adverse_logits = adverse_logits - np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    # The beneficial interpretation reverses the semantic polarity while
    # preserving the same smooth evidence-integration computation.
    beneficial_probs = adverse_probs[::-1]
    polarity_confidence = float(parameters["adverse_polarity_confidence"])
    core_probs = (
        polarity_confidence * adverse_probs
        + (1.0 - polarity_confidence) * beneficial_probs
    )

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=float)
    return probs / total
```

**`policy source code`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / len(probs)
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


## COMPETING THEORY
**Description:** Count-Gated Markedness Minimization theory: decision makers do not automatically interpret a binary 1 as a benefit. Instead, they can adopt a stable markedness schema in which 1 denotes a defect, burden, or potentially misleading positive claim. They first compare the number of marked features and prefer the option with fewer marks, with larger count differences producing stronger preferences. Validity is deliberately ignored at this primary stage. Only when marked counts tie do they consult the highest-validity discriminating feature, treating the option marked on that feature as worse. A subject-level defect-schema-strength parameter represents stable conviction that the task's marked state is adverse rather than an arbitrary free sign; residual activation of the conventional benefit schema produces structured polarity uncertainty. Choice precision and occasional lapses add response variability. The theory predicts that complement-coding the stimuli or explicitly defining 1 as beneficial rather than defective should systematically reverse its choices.

**Parameters:**
- validities: validities
- count_precision: [0.8, 2.4]
- validity_tiebreak_precision: [0.8, 2.4]
- defect_schema_strength: [0.6, 1.0]
- lapse_rate: [0.0, 0.05]

**`predict source code`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Count-Gated Markedness Minimization expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    count_delta = float(np.sum(a) - np.sum(b))

    if count_delta != 0.0:
        # Positive evidence means A carries greater marked-state burden,
        # and therefore supports choosing B. Validity cannot override a
        # difference in the primary marked-feature count.
        evidence_for_b = float(parameters["count_precision"]) * count_delta
    else:
        # On a count tie, inspect the most valid discriminating feature.
        # A mark on that cue is treated as a defect, reversing the usual
        # positive-polarity Take-The-Best interpretation.
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            return np.array([0.5, 0.5], dtype=float)
        order = differing[np.argsort(-validities[differing], kind="stable")]
        j = int(order[0])
        marked_delta = float(a[j] - b[j])
        evidence_for_b = (
            float(parameters["validity_tiebreak_precision"]) * marked_delta
        )

    # Symmetric logits make positive evidence favor B under the defect
    # schema. Stable schema strength mixes this representation with the
    # residual conventional representation in which a mark is beneficial.
    defect_logits = np.array(
        [-0.5 * evidence_for_b, 0.5 * evidence_for_b], dtype=float
    )
    defect_logits = defect_logits - np.max(defect_logits)
    p_defect = np.exp(defect_logits)
    p_defect /= p_defect.sum()

    schema_strength = float(parameters["defect_schema_strength"])
    p_benefit = p_defect[::-1]
    p_core = schema_strength * p_defect + (1.0 - schema_strength) * p_benefit

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * p_core + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return probs
```

**`policy source code`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## DATA SCHEMA
Your metric receives a tidy per-trial pandas DataFrame stacking all subjects (rows grouped by `subject_id`, in trial order). Columns:
- subject_id: Subject identifier (one row per trial per subject).
- option_a_ratings: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
- option_b_ratings: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
- response: 0 if subject chose A, 1 if subject chose B.

## IMPLEMENTATION GUARDRAILS
Any column in the schema above whose description names a list / tuple / np.ndarray (i.e. a per-trial sequence of values) holds non-scalar cells. Those cells are NOT hashable, so operations that hash row values fail with `TypeError: unhashable type: 'list'`. Treating `<seq_col>` as a placeholder for any such sequence-valued column:
- Avoid: `data.groupby('<seq_col>')`, `data['<seq_col>'].value_counts()`,     `data['<seq_col>'].nunique()`, `data['<seq_col>'].unique()` (returns     an object array but downstream `set()` / `in dict` will crash),     `set(data['<seq_col>'])`, `data['<seq_col>'].isin([...])` against list     values, or using a list cell as a dict key.
- If you need a hashable surrogate, project to one first, e.g.:
    - `data['<seq_col>_key'] = data['<seq_col>'].apply(tuple)` then group by `<seq_col>_key`
    - `data['<seq_col>_str'] = data['<seq_col>'].apply(lambda x: ''.join(map(str, x)))`
    Scalar columns (ints, floats, strings like `subject_id`, integer     responses, etc.) hash fine and can be used directly.
- Generator expressions inside function calls like `map()` or `join()` MUST be     parenthesized. For example:
    - WRONG: `map(str, int(v) for v in x)` → SyntaxError
    - RIGHT: `map(str, (int(v) for v in x))` or use a list comp: `[str(int(v)) for v in x]`
- Always verify your code is syntactically valid Python before returning it.

## METRICS YOU ALREADY TRIED AND FAILED ON
Each entry below is a metric you previously proposed in this round that did NOT discriminate the two theories at the human sample size — either it errored, its between-subject variance was unavailable, or Welch's t-test on `(self mean, self var, N)` vs. `(adv mean, adv var, N)` returned p ≥ alpha. The `outcome` line is the simulation result (means, between-subject variances, t-statistic and p-value at the human N) on the same `data_self` / `data_adv` your next metric will be evaluated on. Use the numbers to see where your hypothesised contrast collapsed — small mean gap, large per-subject variance, or both — and propose something qualitatively different. Don't repeat the same idea with cosmetic tweaks.
(none yet)

## RESPONSE FORMAT
Return a JSON object with the following fields:
- metric: Python source defining def metric(data: pd.DataFrame) -> float.
- rationale: Reasoning behind this metric; used when interpreting results.


## Response

```json
{
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    validities = np.array(\n        [0.99, 0.94, 0.89, 0.84, 0.79, 0.74, 0.69, 0.64, 0.59, 0.54, 0.50],\n        dtype=float,\n    )\n\n    if len(data) == 0:\n        return float(\"nan\")\n\n    a = np.vstack(data[\"option_a_ratings\"].apply(lambda z: np.asarray(z, dtype=float)).to_numpy())\n    b = np.vstack(data[\"option_b_ratings\"].apply(lambda z: np.asarray(z, dtype=float)).to_numpy())\n    response = data[\"response\"].to_numpy(dtype=float)\n\n    # Orient each complementary stimulus so that the option marked by the\n    # highest-validity expert is the reference marked option.\n    orientation = np.sign(a[:, 0] - b[:, 0])\n    usable = np.isfinite(response) & (orientation != 0)\n    if np.sum(usable) < 2:\n        return float(\"nan\")\n\n    orientation = orientation[usable]\n    response = response[usable]\n    diff = (a[usable] - b[usable])\n\n    # Weighted markedness of the highest-validity-marked option relative to\n    # its alternative. Complementary presentations receive the same x value.\n    x = orientation * np.dot(diff, validities)\n\n    # One means choosing the option unmarked by the highest-validity expert.\n    y = np.where(orientation > 0, response, 1.0 - response)\n\n    # Within-data OLS slope. Centering removes the competitor's subject-level\n    # but condition-invariant preference for the unmarked option.\n    xc = x - np.mean(x)\n    denom = float(np.dot(xc, xc))\n    if not np.isfinite(denom) or denom <= 0.0:\n        return float(\"nan\")\n    return float(np.dot(xc, y - np.mean(y)) / denom)\n",
  "rationale": "This metric is the slope of choosing the option unmarked by the 0.99-validity expert against the full validity-weighted markedness difference. Complementary A/B presentations are recoded to the same orientation, removing response-side effects. Count-Gated Markedness Minimization predicts a condition-invariant choice probability because every trial is a count tie and the same highest-validity cue controls its tiebreak; consequently, its expected slope is zero even when schema strength differs across subjects. Smooth Integration predicts a positive graded slope because its choice probability varies continuously with the weighted difference across all six conditions. The centered within-subject slope also cancels stable subject-level response tendencies, while all 96 trials contribute to estimation, improving precision relative to an endpoint-only contrast."
}
```

## Usage

```json
{
  "input_tokens": 4710,
  "output_tokens": 2197
}
```
