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
**Validities (n_features=13):** [0.99, 0.95, 0.9, 0.85, 0.78, 0.72, 0.7, 0.68, 0.67, 0.66, 0.58, 0.56, 0.51]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  trial 2: A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 0, 0]
  trial 3: A=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]
  trial 4: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0]

**Rationale:** This is a fixed-load, fixed-direction-sequence coalition-strength test. Every base trial has exactly five discriminating experts, encountered in descending instructed-validity order as A,A,A,B,B. Thus the local commitment ends in favor of B, the unweighted count favors A by 3–2, and discriminating-cue count, update fatigue, terminal direction, and directional sequence are identical across conditions. Only the validities of the five discriminating experts change. The weak coalition uses nearly matched 72%–66% experts; the intermediate coalition gives A three substantially stronger experts than B; and the strong coalition gives A the 99%, 95%, and 90% experts while B receives the 56% and 51% experts. Recency-Gated Reason Overwrite does not use validity magnitudes after establishing scan order, so it predicts exactly the same B-choice probability in all three base conditions. Load-Contingent Dual-Code Arbitration instead predicts a pronounced validity-coalition gradient at the manageable load of five reasons. The weak weighted coalition should generally fail selectivity, leaving the terminal-B local code dominant; intermediate and especially strong A coalitions should increasingly recruit the global code and can reverse choice toward A because that code opposes the local commitment. The critical signature is therefore increasing choice of the 3–2 majority option from weak through intermediate to strong coalition strength, potentially crossing 0.50, against the overwrite theory's flat terminal-B profile. Exact A/B reversals balance response side. Six unique pairs repeated 16 times yield 96 trials.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Load-Contingent Dual-Code Arbitration. While inspecting discriminating experts in instructed-validity order, a decision maker constructs two qualitatively different codes. The local code is a rapidly revised categorical commitment: each new discriminating reason almost completely replaces the previous commitment, so reasons outside the recent suffix become functionally absent rather than merely weakened traces. In parallel, the person can form a validity-weighted global coalition summary that preserves cumulative directional evidence without preserving cue order. Choice is governed by smooth arbitration between these codes. Global comparison is recruited only after conflict is sufficiently elaborate to warrant comparison, is favored when validity-weighted evidence forms a diagnostic coalition supported by an unweighted directional majority, and loses accessibility when subject-specific effective capacity is exceeded. Coalition selectivity is itself load-contingent: a coalition must be especially strong near the recruitment boundary, whereas weaker cumulative coalitions become usable inside the subject's manageable comparison window before becoming inaccessible under overload. Within that manageable window, global control receives a selective increment when the global coalition opposes the current local commitment, because only such disagreement warrants effortful comparison. Thus short or count-balanced conflicts are dominated by local revision, manageable majority-coalition conflicts can be decided cumulatively, and overloaded conflicts revert toward an uncertainty-attenuated recent commitment. Capacity, recruitment threshold, coalition selectivity, and local and global gains are stable subject characteristics shared across trials.

**Parameters:**
- validities: validities
- effective_capacity: [5.8, 6.8]
- recruitment_threshold: [3.1, 4.0]
- arbitration_temperature: [0.35, 0.75]
- local_retention: [0.0, 0.04]
- local_gain: [1.35, 2.15]
- global_gain: [2.0, 4.2]
- validity_sensitivity: [0.65, 1.35]
- coalition_focus: [0.75, 1.65]
- overload_attenuation: [0.8, 1.6]
- lapse_rate: [0.03, 0.14]

**`predict source code`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Dual-code arbitration expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    capacity = float(parameters["effective_capacity"])
    recruitment_threshold = float(parameters["recruitment_threshold"])
    arbitration_temperature = float(parameters["arbitration_temperature"])
    local_retention = float(parameters["local_retention"])
    local_gain = float(parameters["local_gain"])
    global_gain = float(parameters["global_gain"])
    validity_sensitivity = float(parameters["validity_sensitivity"])
    coalition_focus = float(parameters["coalition_focus"])
    overload_attenuation = float(parameters["overload_attenuation"])
    lapse = float(parameters["lapse_rate"])

    diff = stim[0] - stim[1]
    cue_order = np.argsort(-validities, kind="stable")
    discriminating = [int(j) for j in cue_order if diff[j] != 0]
    m = len(discriminating)
    if m == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    directions = np.asarray(
        [float(np.sign(diff[j])) for j in discriminating], dtype=float
    )

    # LOCAL CODE: a categorical commitment rather than a common evidence
    # buffer. Every newly encoded reason installs its own direction and only
    # a small residue of the immediately preceding commitment remains.
    # Consequently, sufficiently early reasons are functionally absent.
    local_commitment = 0.0
    for direction in directions:
        local_commitment = direction + local_retention * local_commitment
    local_commitment = float(np.clip(local_commitment, -1.5, 1.5))

    # GLOBAL CODE: cumulative validity-weighted coalition evidence. Log odds
    # represent communicated reliability, while normalization makes the code
    # portable across experiments with different absolute validity scales.
    v = np.clip(validities[discriminating], 0.5001, 0.999)
    reliability = np.log(v / (1.0 - v))
    positive = reliability[reliability > 0.0]
    scale = float(np.mean(positive)) if positive.size else 1.0
    if not np.isfinite(scale) or scale <= 0.0:
        scale = 1.0
    weights = np.power(
        np.clip(reliability / scale, 1e-4, 20.0), validity_sensitivity
    )
    weights = np.clip(weights, 1e-5, 30.0)

    signed_global = float(np.sum(weights * directions))
    global_norm = float(np.sqrt(np.sum(weights * weights)))
    if not np.isfinite(global_norm) or global_norm <= 0.0:
        global_norm = 1.0
    global_summary = signed_global / global_norm

    total_weight = float(np.sum(weights))
    coalition_strength = abs(signed_global) / max(total_weight, 1e-9)
    coalition_strength = float(np.clip(coalition_strength, 0.0, 1.0))

    # Conflict balance is high when both options have several reasons. It is
    # arrangement-free: only directional masses enter, never switch counts or
    # directional runs.
    positive_mass = float(np.sum(weights[directions > 0.0]))
    negative_mass = float(np.sum(weights[directions < 0.0]))
    if positive_mass + negative_mass <= 0.0:
        conflict_balance = 0.0
    else:
        conflict_balance = (
            2.0 * min(positive_mass, negative_mass)
            / (positive_mass + negative_mass)
        )
    conflict_balance = float(np.clip(conflict_balance, 0.0, 1.0))

    temp = max(arbitration_temperature, 1e-6)

    # Recruitment rises smoothly once a conflict warrants an explicit global
    # comparison, but global accessibility falls smoothly near the person's
    # effective capacity. No fixed cue-count boundary is imposed.
    onset_x = np.clip((float(m) - recruitment_threshold) / temp, -60.0, 60.0)
    onset = 1.0 / (1.0 + np.exp(-onset_x))
    capacity_x = np.clip((capacity - float(m)) / temp, -60.0, 60.0)
    accessibility = 1.0 / (1.0 + np.exp(-capacity_x))

    # Validity weighting determines the content of the global summary, but
    # recruitment also requires an unweighted directional coalition. A
    # smooth, nonsaturating transform gives a one-vote majority only partial
    # diagnosticity, while preserving exact protection for count balance and
    # approaching full support only for genuinely lopsided coalitions.
    raw_count_coalition = abs(float(np.sum(directions))) / float(m)
    raw_count_coalition = float(np.clip(raw_count_coalition, 0.0, 1.0))
    count_coalition = (
        (1.0 - np.exp(-2.0 * raw_count_coalition))
        / (1.0 - np.exp(-2.0))
    )
    count_coalition = float(np.clip(count_coalition, 0.0, 1.0))

    # Coalition selectivity varies smoothly with effective load. Near the
    # subject's recruitment boundary, only a strong weighted coalition can
    # engage global comparison. Once load is clearly above that boundary but
    # still below effective capacity, weaker cumulative coalitions become
    # usable. Selectivity tightens again as overload approaches. The window is
    # defined relative to stable subject-specific thresholds rather than by a
    # fixed number of cues.
    comparison_x = np.clip(
        (float(m) - recruitment_threshold - 0.75) / temp, -60.0, 60.0
    )
    comparison_ready = 1.0 / (1.0 + np.exp(-comparison_x))
    pre_overload_x = np.clip(
        (capacity + 0.50 - float(m)) / temp, -60.0, 60.0
    )
    pre_overload_access = 1.0 / (1.0 + np.exp(-pre_overload_x))
    manageable_window = comparison_ready * pre_overload_access
    selectivity_cutoff = 0.56 - 0.30 * manageable_window

    weighted_selectivity_x = np.clip(
        (coalition_strength - selectivity_cutoff) / 0.12, -60.0, 60.0
    )
    weighted_selectivity = 1.0 / (1.0 + np.exp(-weighted_selectivity_x))
    diagnosticity = np.power(
        np.clip(coalition_strength, 0.0, 1.0), coalition_focus
    )
    diagnosticity *= count_coalition * weighted_selectivity
    diagnosticity = float(np.clip(diagnosticity, 0.0, 1.0))

    global_gate = float(np.clip(onset * accessibility * diagnosticity, 0.0, 1.0))

    # Effortful global arbitration is selectively useful when its cumulative
    # conclusion opposes the current local commitment. A bounded additive
    # increment can rescue a weak baseline gate inside the manageable window,
    # while count support, weighted selectivity, and accessibility suppress it
    # near recruitment, in balanced displays, and under overload.
    code_opposition = 0.5 * (
        1.0 - np.tanh(local_commitment * global_summary / 0.20)
    )
    opposition_window = manageable_window * manageable_window * pre_overload_access
    opposition_increment = (
        0.95
        * accessibility
        * accessibility
        * opposition_window
        * code_opposition
        * count_coalition
        * weighted_selectivity
    )
    global_gate += opposition_increment
    global_gate = float(np.clip(global_gate, 0.0, 1.0))

    # Capacity pressure attenuates expression of the local commitment. Its
    # smooth onset slightly precedes nominal capacity, reflecting the cost of
    # maintaining both codes before capacity is completely exceeded.
    overload = temp * np.logaddexp(
        0.0, (float(m) - capacity + 0.75) / temp
    )
    local_divisor = np.sqrt(1.0 + overload_attenuation * overload * overload)
    local_dv = local_gain * local_commitment / local_divisor
    global_dv = global_gain * global_summary

    decision_variable = (
        (1.0 - global_gate) * local_dv + global_gate * global_dv
    )
    decision_variable = float(np.clip(decision_variable, -60.0, 60.0))

    p_a = 1.0 / (1.0 + np.exp(-decision_variable))
    core = np.array([p_a, 1.0 - p_a], dtype=np.float64)
    probs = (1.0 - lapse) * core + lapse * np.array([0.5, 0.5])

    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total
```

**`policy source code`:**
```python
def policy(probs) -> int:
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
**Description:** Recency-Gated Reason Overwrite with Processing Fatigue. People inspect cues sequentially in descending order of instructed validity and continue after finding a discriminating cue. An attended discriminating cue establishes a provisional choice, and each subsequently attended discriminating cue can overwrite that choice. Consequently, the final attended reason has disproportionate control. Occasional failures to attend a cue preserve an earlier reason, while response lapses dilute strong recency effects. In addition, processing more than two discriminating reasons produces task-invariant update fatigue: the retained decision is expressed with progressively lower reliability as the discriminating-cue count increases. This preserves strong second-reason overwrite on short conflicts while moderating near-deterministic last-reason control on longer sequences.

**Parameters:**
- validities: validities
- cue_attention: [0.95, 1.0]
- overwrite_rate: [0.95, 1.0]
- update_fatigue: [0.06, 0.17]
- lapse_rate: [0.15, 0.41]

**`predict source code`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Recency-Gated Reason Overwrite expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    attention = float(parameters["cue_attention"])
    overwrite = float(parameters["overwrite_rate"])
    fatigue = float(parameters["update_fatigue"])
    lapse = float(parameters["lapse_rate"])

    # Stable sorting represents the displayed high-to-low validity scan;
    # ties retain their display order.
    cue_order = np.argsort(-validities, kind="stable")
    diff = stim[0] - stim[1]

    # Exact marginal distribution over the provisional state:
    # A selected, B selected, or no discriminating cue encoded yet.
    p_a, p_b, p_uncommitted = 0.0, 0.0, 1.0
    discriminating_count = 0

    for j in cue_order:
        direction = diff[j]
        if direction == 0:
            continue

        discriminating_count += 1
        old_a, old_b, old_u = p_a, p_b, p_uncommitted

        if direction > 0:
            # An attended A cue initializes an uncommitted decision and
            # overwrites a conflicting B decision with the overwrite rate.
            p_a = old_a + attention * overwrite * old_b + attention * old_u
            p_b = old_b * (1.0 - attention * overwrite)
            p_uncommitted = old_u * (1.0 - attention)
        else:
            p_b = old_b + attention * overwrite * old_a + attention * old_u
            p_a = old_a * (1.0 - attention * overwrite)
            p_uncommitted = old_u * (1.0 - attention)

    # If no discriminating cue was encoded, either response is an equal guess.
    p_core = np.array([
        p_a + 0.5 * p_uncommitted,
        p_b + 0.5 * p_uncommitted
    ], dtype=np.float64)

    # Processing the first reason and its immediate successor is reliable.
    # Additional discriminating updates progressively weaken expression of
    # the retained choice without disrupting the crucial second-cue reversal.
    excess_updates = max(0, discriminating_count - 2)
    retention = (1.0 - fatigue) ** excess_updates
    p_core = retention * p_core + (1.0 - retention) * np.array([0.5, 0.5])

    # Independent execution/inattention lapse.
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    \"\"\"Side-balanced rate of choosing the 3-to-2 majority in strong-coalition trials.\"\"\"\n    majority_a = []\n    majority_b = []\n    strong_set = {0, 1, 2, 11, 12}\n\n    for _, row in data.iterrows():\n        a = np.asarray(row[\"option_a_ratings\"], dtype=float)\n        b = np.asarray(row[\"option_b_ratings\"], dtype=float)\n        diff = a - b\n        discriminating = set(np.flatnonzero(diff != 0).tolist())\n        if discriminating != strong_set:\n            continue\n\n        response = int(row[\"response\"])\n        majority_direction = float(np.sum(np.sign(diff)))\n        if majority_direction > 0:\n            majority_a.append(float(response == 0))\n        elif majority_direction < 0:\n            majority_b.append(float(response == 1))\n\n    if majority_a and majority_b:\n        return float(0.5 * (np.mean(majority_a) + np.mean(majority_b)))\n\n    pooled = majority_a + majority_b\n    if pooled:\n        return float(np.mean(pooled))\n    return 0.5\n",
  "rationale": "This measures how often subjects choose the three-cue majority option specifically in the strongest coalition and averages the two exact A/B orientations equally. In these trials, the majority is supported by the 99%, 95%, and 90% experts, whereas the minority is supported only by the 56% and 51% experts. Dual-code arbitration predicts frequent majority choices because the strong validity-weighted global coalition can overturn the terminal minority-favoring local commitment. Overwrite predicts the opposite: the common A,A,A,B,B direction sequence leaves the terminal minority reasons in control and does not use the large validity gap. Restricting the score to the strongest coalition maximizes the predicted separation, while 32 repeated observations per subject and side balancing keep its between-subject sampling variance relatively small."
}
```

## Usage

```json
{
  "input_tokens": 6237,
  "output_tokens": 2803
}
```
