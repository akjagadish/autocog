# generation_iter_00_attempt_00

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a new theory and its model instantiation in the Decision Making (Binary Features) domain based on the feedback provided by an arbiter. The feedback contains diagnoses of mechanistic failures of the previous theory along with suggestions for a new theory family that overcomes those failures. The newly proposed theory and model should display human-like behavior when simulated on experiment(s). 
The goal of the theory generation process is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across the majority of experiments. 
You will see a list of theories that have been proposed in the past but you should only use them as inspiration and not to choose from them. Propose a new theory that is different. 
If they fail to do so, you will receive feedback on their performance on the same experiment(s) and you will have to propose another new theory and model that meet the requirements, iterating until you succeed.

If you think the failure to capture human behavior is due to arbiter feedback that is inaccurate or unhelpful, you can propose a new theory and model that ignore the feedback, but you must provide rationale for why you are ignoring it and how your proposal overcomes the identified mechanistic failures.

## ACCEPT GATE & LOSS TRAJECTORY — HOW THE LOOP HANDLES YOUR EDITS
This propose-loop has a programmatic accept gate: after every iteration the candidate's `aggregate_loss` is compared against the running-best loss; strict improvement -> ACCEPTED (the candidate becomes the new running-best base); otherwise -> REJECTED (the candidate is discarded and the base is unchanged). You do NOT need to manually "revert" a regressed edit — the gate already does that for you.

The block rendered below as `## PREVIOUS CANDIDATE (this loop)` is ALWAYS the running-best (last ACCEPTED) candidate, NEVER your most recent attempt if it was rejected. So:
  * Treat `## PREVIOUS CANDIDATE` as a known-good base. Build on it.
  * The `## LOSS TRAJECTORY` block tags every iteration ACCEPTED or REJECTED. Use this as ground truth on which past critic advice actually moved the loop forward and which didn't.
  * The `## PRIOR FEEDBACK ITERATIONS` block annotates each prior critique with the same ACCEPTED/REJECTED tag of the candidate it elicited. Down-weight critic advice whose previous candidates were REJECTED, and reinforce / extend advice whose candidates were ACCEPTED.
  * Treat the best ACCEPTED iteration's loss as a soft floor — the next edit should plausibly land at-or-below it, otherwise the gate will reject your attempt and the base stays put.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

## PARAMETER NOTATION
`parameters` is a JSON object mapping each parameter name (snake_case string) to a *string* value that specifies its domain. Every value MUST be a string — never a bare list, number, tuple, or expression. Use exactly one of these notations per parameter:

1. Continuous interval — square brackets, two numeric bounds:
   "[min, max]"
   Examples: "[0, 1]", "[1.0, 10.0]", "[10, 1000]"

2. Discrete set — curly braces, comma-separated values:
   "{v1, v2, ...}"
   Example: "{1, 2}"

3. Vector of intervals whose length is set by the experiment — a bracketed tuple repeated by a symbolic length variable:
   "[(min, max)] * length_var"
   Example: "[(0, 1)] * n_features"

4. Symbolic reference — a bare variable name (no brackets, no angle brackets), used when the parameter takes its value from an experiment-defined constant rather than a range:
   "variable_name"
   Example: "n_features"

Rules:
- Do not use parentheses for intervals; square brackets only. Tuples `(a, b)` are reserved for the vector-of-intervals notation in (3).
- Do not mix notations within a single value (e.g., no "[0, 1] or {2, 3}").
- Do not quote numbers inside the notation (write "[0, 1]", not "['0', '1']").
- Every parameter referenced by `predict` or `policy` must appear as a key in `parameters`, and vice versa.
- Notations 3 and 4 may ONLY reference the experiment-defined symbolic identifiers listed under "ALLOWED SYMBOLIC IDENTIFIERS" below. Do not invent new identifier names. If a parameter's shape doesn't fit any of those variables, fall back to a literal interval (notation 1) or discrete set (notation 2). Use these names so the model adapts to any experiment in this domain instead of hardcoding shapes.

## ALLOWED SYMBOLIC IDENTIFIERS (for notations 3 and 4 above)
- n_features: Number of expert ratings per option (LLM-proposed via `validities` length).
- validities: Per-expert validities (LLM-proposed; each in [0.5, 1.0]); fixed across all trials.

## AVAILABLE IMPORTS inside `predict` and `policy`
- numpy as np
- pandas as pd
- scipy and its submodules
- torch and torch.nn.functional as F
- sklearn and its submodules
- math, random, and other standard Python libraries

## RUNTIME CONTRACT (function signatures and argument shapes)
`predict(parameters, state, history) -> np.ndarray`:
- `parameters`: dict[str, value]. One sample drawn from your declared `parameters` ranges, applied for the entire subject run.
- `state`: the per-trial input delivered by the experiment (shape is domain-specific — see the experiment description above and the `history` key list below, which mirrors the per-trial variables carried in `state`). Convert to an array with `np.asarray(state)` if you need array ops.
- `history`: dict-of-lists for past trials in this subject's run, NOT a list-of-dicts. The per-trial keys are:
  Each value below is a Python list in trial order; entry `i` is the value for trial `i`. On the first trial all lists are empty.
  - `"option_a_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
  - `"option_b_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
  - `"response"`: 0 if subject chose A, 1 if subject chose B.
Iterating `for x in history:` iterates the dict KEYS (strings); to walk trials index the lists in lock-step, e.g. `for i in range(len(next(iter(history.values())))): ...`.
- Returns: 1-D `np.ndarray` of choice probabilities over the experiment's discrete action set, summing to 1.

`policy(probs) -> int`:
- Receives the probability vector produced by `predict`.
- Returns: integer index in `[0, len(probs))` identifying the chosen action. If you sample with `np.random.choice(..., p=probs)`, normalise first (`probs = np.asarray(probs, dtype=np.float64); probs /= probs.sum()`) to avoid the "probabilities do not sum to 1" ValueError from float drift.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_3`
- THEORY 2 = `pi_4`
- The recommendation below acts on THEORY 1 (= `pi_3`).

Replace pi_3 with a task-invariant hierarchical audit theory of adverse markedness. Subjects should first form a provisional preference from the marked-count difference, but validity information must remain continuously available rather than being excluded on non-ties. Its influence should be modulated by trial structure: use a nonzero baseline validity gain on count ties and a stronger discrepancy-triggered validity audit when counts differ, allowing the validity slope to be larger in Experiment 1 than in Experiment 2. A suitable evidence architecture is an adverse-polarity signal combining a nonlinear count term with a count-margin-modulated, count-residualized validity term, for example E = alpha*f(count_difference) + beta*g(abs(count_difference))*residualized_validity_difference, with g(0) greater than zero and g(1) permitted to exceed g(0). The count function should become strong or saturating at large margins, preserving the markedness choices in Experiments 3, 5, and 6. Include stable subject-level variation in count reliance, validity-audit propensity, semantic polarity, precision, and lapse rate to reproduce the consistently elevated observed variances. This theory differs from pi_3 by rejecting the hard count gate and differs from pi_4 by making validity gain structurally conditional rather than uniformly smooth. It should be tested against pi_4 using joint parameter constraints across all experiments, especially the requirement to produce approximately 0.23 validity sensitivity for one-mark count conflicts while producing only approximately 0.11 on equal-count redistributions.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_3` (overall score: 0.587)

**Description**
Count-Gated Markedness Minimization theory: decision makers do not automatically interpret a binary 1 as a benefit. Instead, they can adopt a stable markedness schema in which 1 denotes a defect, burden, or potentially misleading positive claim. They first compare the number of marked features and prefer the option with fewer marks, with larger count differences producing stronger preferences. Validity is deliberately ignored at this primary stage. Only when marked counts tie do they consult the highest-validity discriminating feature, treating the option marked on that feature as worse. A subject-level defect-schema-strength parameter represents stable conviction that the task's marked state is adverse rather than an arbitrary free sign; residual activation of the conventional benefit schema produces structured polarity uncertainty. Choice precision and occasional lapses add response variability. The theory predicts that complement-coding the stimuli or explicitly defining 1 as beneficial rather than defective should systematically reverse its choices.

`predict(parameters, state, history) -> np.ndarray`:
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


`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- validities: validities
- count_precision: [0.8, 2.4]
- validity_tiebreak_precision: [0.8, 2.4]
- defect_schema_strength: [0.6, 1.0]
- lapse_rate: [0.0, 0.05]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4355 (var=0.0764) vs this=-0.4570 (var=0.0555)
- Experiment 2: real=0.0000 (var=0.0000) vs this=0.0000 (var=0.0000)
- Experiment 3: real=0.7367 (var=0.0520) vs this=0.6383 (var=0.0899)
- Experiment 4: real=-0.4825 (var=0.0708) vs this=-0.4696 (var=0.0469)
- Experiment 5: real=0.2306 (var=0.0353) vs this=0.0002 (var=0.0045)
- Experiment 6: real=0.1062 (var=0.0136) vs this=0.0054 (var=0.0029)


---

### `pi_4` (overall score: 0.510)

**Description**
Semantic-Polarity Smooth Integration theory: people first interpret what the marked binary state means rather than assuming that 1 is intrinsically desirable. Each subject forms a stable posterior belief that a mark is adverse or suspicious. Conditional on either the adverse interpretation or its residual beneficial alternative, the subject smoothly integrates two continuous signals: the difference in total marks and a partially count-residualized validity-weighted difference. The count signal normally dominates, while the weighted signal supplies graded sensitivity to which experts carry the marks on every trial. The two semantic interpretations generate opposite choice distributions, which are averaged according to the subject's polarity confidence. A small lapse process captures stimulus-independent errors.

`predict(parameters, state, history) -> np.ndarray`:
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


`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / len(probs)
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- validities: validities
- count_weight: [0.38, 1.05]
- validity_weight: [0.7, 1.8]
- partial_centering: [0.1, 0.3]
- adverse_polarity_confidence: [0.78, 1.0]
- lapse_rate: [0.0, 0.12]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4355 (var=0.0764) vs this=-0.3570 (var=0.0237)
- Experiment 2: real=0.0000 (var=0.0000) vs this=0.0000 (var=0.0000)
- Experiment 3: real=0.7367 (var=0.0520) vs this=0.7317 (var=0.0354)
- Experiment 4: real=-0.4825 (var=0.0708) vs this=-0.5396 (var=0.0205)
- Experiment 5: real=0.2306 (var=0.0353) vs this=0.2053 (var=0.0075)
- Experiment 6: real=0.1062 (var=0.0136) vs this=0.2086 (var=0.0061)


---

### `pi_1` (overall score: 0.121)

**Description**
People compare two options by consulting cues one at a time in order of validity, stopping at the first cue that discriminates between the two options. That cue alone determines the choice: the option with the higher value on the discriminating cue wins, and no other cue is consulted. Cues with lower validity are never reached when a higher-validity cue already discriminates, so Take The Best is a "one-reason" decision rule — only a single feature is ever used on any given choice. Because only the sign of the comparison on the top discriminating cue matters, TTB ignores both the magnitude of that difference and all information on lower-validity cues, making it maximally frugal in the use of evidence. Cue validities are subjective and can be learned, inferred from instructions, or fixed by task structure. When no cue discriminates (all feature-wise comparisons tie) the learner has no basis for preference and must guess. Response noise enters through a softmax over the binary TTB score (winner = 1, loser = 0) with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Take The Best (Gigerenzer & Goldstein 1996).
    # Stimulus is the pair of option feature vectors for the current
    # trial: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B. Cue cascade: features are consulted in order
    # of descending validity; the first discriminating cue (strict
    # inequality) determines the winner; if no cue discriminates,
    # the model guesses uniformly. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )
    # Descending validity; argsort is stable so validity ties break
    # toward the earlier feature index.
    cue_order = np.argsort(-val, kind="stable").tolist()

    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        if b[j] > a[j]:
            winner = 1
            break

    if winner is None:
        # No discriminating cue — pure guess.
        return np.ones(2) / 2.0

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the
    # binary TTB score this collapses to sigmoid(beta) for the winner,
    # giving a direct mapping from beta onto the paper's flip-noise
    # levels (beta=0 ↔ 50/50; beta ≫ 1 ↔ deterministic).
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4355 (var=0.0764) vs this=-0.0052 (var=0.0117)
- Experiment 2: real=0.0000 (var=0.0000) vs this=1.0000 (var=0.0900)
- Experiment 3: real=0.7367 (var=0.0520) vs this=-0.6600 (var=0.0730)
- Experiment 4: real=-0.4825 (var=0.0708) vs this=-0.6617 (var=0.0574)
- Experiment 5: real=0.2306 (var=0.0353) vs this=-0.2514 (var=0.0060)
- Experiment 6: real=0.1062 (var=0.0136) vs this=0.0091 (var=0.0021)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0, 0, 0]  B=[0, 1, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1, 0, 0]  B=[1, 0, 1, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 1, 1]  B=[1, 0, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    aligned = []
    tally_margins = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)

        # Validities are strictly descending in feature order, so the first
        # feature that differs identifies the Take-The-Best winner.
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            continue
        j = int(differing[0])
        ttb_winner = 0 if a[j] > b[j] else 1

        a_wins = int(np.sum(a > b))
        b_wins = int(np.sum(b > a))
        tally_margins.append(abs(a_wins - b_wins))
        aligned.append(float(int(row["response"]) == ttb_winner))

    if len(aligned) == 0:
        return float("nan")

    aligned = np.asarray(aligned, dtype=float)
    tally_margins = np.asarray(tally_margins, dtype=int)
    tie = tally_margins == 0
    conflict = tally_margins > 0

    if not np.any(tie) or not np.any(conflict):
        return float("nan")

    # Tally-margin sensitivity: excess TTB agreement on tally ties relative
    # to trials where the tally favors the opposite option.
    return float(np.mean(aligned[tie]) - np.mean(aligned[conflict]))
```

**Observed (real) value:** -0.4355 (var=0.0764)
**Other theories' values on this metric (for reference):**
- pi_1: -0.0052 (var=0.0117)
- pi_2: 0.3523 (var=0.0241)
- pi_3: -0.4570 (var=0.0555)
- pi_4: -0.3570 (var=0.0237)

### Experiment 2
**Design**
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Score each choice against the winner designated by the highest-validity
    # discriminating cue. Validities are strictly decreasing with feature index.
    signed_scores = []

    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"]
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            continue

        first = int(differing[0])
        ttb_winner = 0 if a[first] > b[first] else 1
        signed_scores.append(1.0 if int(response) == ttb_winner else -1.0)

    if not signed_scores:
        return float("nan")

    alignment = float(np.mean(signed_scores))

    # This corresponds to choosing the validity-ordered winner on more than
    # 62.5% of trials. It is well beyond ordinary finite-sample fluctuation
    # around Tallying's predicted 50%, while remaining below typical TTB rates.
    return float(alignment > 0.25)

```

**Observed (real) value:** 0.0000 (var=0.0000)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0000 (var=0.0000)
- pi_1: 1.0000 (var=0.0900)
- pi_3: 0.0000 (var=0.0000)
- pi_4: 0.0000 (var=0.0000)

### Experiment 3
**Design**
  A=[1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1, 1, 0]  B=[0, 0, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 1]  B=[0, 0, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    scores = []
    for a_cell, b_cell, response in zip(
        data["option_a_ratings"],
        data["option_b_ratings"],
        data["response"]
    ):
        a = np.asarray(a_cell, dtype=float)
        b = np.asarray(b_cell, dtype=float)
        count_delta = float(np.sum(a) - np.sum(b))

        # Restrict attention to the strongly diagnostic count-margin trials.
        if abs(count_delta) >= 5.0:
            response_sign = 2.0 * float(response) - 1.0  # B=+1, A=-1
            scores.append(float(np.sign(count_delta) * response_sign))

    if len(scores) == 0:
        return 0.0
    return float(np.mean(scores))
```

**Observed (real) value:** 0.7367 (var=0.0520)
**Other theories' values on this metric (for reference):**
- pi_3: 0.6383 (var=0.0899)
- pi_2: -0.7000 (var=0.0639)
- pi_1: -0.6600 (var=0.0730)
- pi_4: 0.7317 (var=0.0354)

### Experiment 4
**Design**
  A=[0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Weighted choice alignment with the feature-count majority."""
    if data is None or len(data) == 0:
        return 0.0

    weighted_scores = []
    weights = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        count_delta = float(np.sum(a) - np.sum(b))

        # Count ties do not identify a tallying preference and are omitted.
        if count_delta == 0.0:
            continue

        response = int(row["response"])
        # +1 when the option with more positive ratings was selected,
        # -1 when the option with fewer positive ratings was selected.
        choice_sign = 1.0 if response == 0 else -1.0
        alignment = choice_sign * np.sign(count_delta)

        # Margin-two trials receive more weight because both theories make
        # more precise, oppositely directed predictions on them.
        weight = abs(count_delta)
        weighted_scores.append(weight * alignment)
        weights.append(weight)

    if not weights:
        return 0.0
    return float(np.sum(weighted_scores) / np.sum(weights))

```

**Observed (real) value:** -0.4825 (var=0.0708)
**Other theories' values on this metric (for reference):**
- pi_2: 0.7229 (var=0.0432)
- pi_3: -0.4696 (var=0.0469)
- pi_1: -0.6617 (var=0.0574)
- pi_4: -0.5396 (var=0.0205)

### Experiment 5
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array(
        [1.0, 0.98, 0.96, 0.94, 0.92, 0.58, 0.56, 0.54, 0.52, 0.5, 0.5],
        dtype=float,
    )

    validity_advantage = []
    chose_fewer_marks = []

    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        response = int(row["response"])

        count_a = float(a.sum())
        count_b = float(b.sum())

        if count_a > count_b:
            # A is the option with more marks; B has fewer marks.
            rich_minus_sparse = a - b
            fewer_choice = float(response == 1)
        elif count_b > count_a:
            # B is the option with more marks; A has fewer marks.
            rich_minus_sparse = b - a
            fewer_choice = float(response == 0)
        else:
            # Not expected in this design, but omit count ties safely.
            continue

        validity_advantage.append(float(np.dot(validities, rich_minus_sparse)))
        chose_fewer_marks.append(fewer_choice)

    x = np.asarray(validity_advantage, dtype=float)
    y = np.asarray(chose_fewer_marks, dtype=float)
    if x.size < 2:
        return 0.0

    x_centered = x - x.mean()
    denominator = float(np.dot(x_centered, x_centered))
    if denominator <= 0.0 or not np.isfinite(denominator):
        return 0.0

    # OLS slope of choosing the fewer-mark option on the validity-weighted
    # advantage held by the more-marked option.
    return float(np.dot(x_centered, y - y.mean()) / denominator)

```

**Observed (real) value:** 0.2306 (var=0.0353)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0002 (var=0.0045)
- pi_4: 0.2053 (var=0.0075)
- pi_1: -0.2514 (var=0.0060)
- pi_2: -0.0002 (var=0.0032)

### Experiment 6
**Design**
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 1, 1, 0, 1]  B=[0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 1, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array(
        [0.99, 0.94, 0.89, 0.84, 0.79, 0.74, 0.69, 0.64, 0.59, 0.54, 0.50],
        dtype=float,
    )

    if len(data) == 0:
        return float("nan")

    a = np.vstack(data["option_a_ratings"].apply(lambda z: np.asarray(z, dtype=float)).to_numpy())
    b = np.vstack(data["option_b_ratings"].apply(lambda z: np.asarray(z, dtype=float)).to_numpy())
    response = data["response"].to_numpy(dtype=float)

    # Orient each complementary stimulus so that the option marked by the
    # highest-validity expert is the reference marked option.
    orientation = np.sign(a[:, 0] - b[:, 0])
    usable = np.isfinite(response) & (orientation != 0)
    if np.sum(usable) < 2:
        return float("nan")

    orientation = orientation[usable]
    response = response[usable]
    diff = (a[usable] - b[usable])

    # Weighted markedness of the highest-validity-marked option relative to
    # its alternative. Complementary presentations receive the same x value.
    x = orientation * np.dot(diff, validities)

    # One means choosing the option unmarked by the highest-validity expert.
    y = np.where(orientation > 0, response, 1.0 - response)

    # Within-data OLS slope. Centering removes the competitor's subject-level
    # but condition-invariant preference for the unmarked option.
    xc = x - np.mean(x)
    denom = float(np.dot(xc, xc))
    if not np.isfinite(denom) or denom <= 0.0:
        return float("nan")
    return float(np.dot(xc, y - np.mean(y)) / denom)

```

**Observed (real) value:** 0.1062 (var=0.0136)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2086 (var=0.0061)
- pi_3: 0.0054 (var=0.0029)
- pi_1: 0.0091 (var=0.0021)
- pi_2: 0.0039 (var=0.0034)


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL
Propose a novel theory from scratch based on all the information available, faithfully implementing the mechanism family the arbiter prescribed above. Do NOT simply reuse anything generated in past rounds.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- theory: The theoretical claim this theory makes about cognition.
- predict: Python source defining def predict(parameters, state, history) -> np.ndarray.
- policy: Python source defining def policy(probs) -> int.
- parameters: Parameter ranges (e.g. "[1.0, 10.0]") or choices (e.g. "{1, 2}"), sampled per subject.
- rationale: Reasoning behind this theory design; used to explain why this theory is better then the previous ones.


## Response

```json
{
  "theory": "Discrepancy-Evoked Residual Audit theory: people make binary-feature choices using a hierarchical but non-gated process. They first construct a provisional preference from the difference in the number of marked states, interpreting marks as adverse by default. This count signal is nonlinear and saturates, so sufficiently large count margins yield a stable preference for the less-marked option. Validity information nevertheless remains continuously available. It is represented as a validity-weighted difference after removing the component that merely duplicates total mark count. On equal-count trials this residual signal receives a nonzero baseline gain. A small count discrepancy triggers an additional audit because it creates a plausible conflict between the provisional tally and the identities of the experts supporting it. Audit gain is strongest near a one-mark discrepancy and declines at large margins, where further scrutiny is unlikely to overturn the strong count judgment. Subjects differ stably in count reliance, audit propensity, semantic polarity, response precision, and lapse rate. Thus, the model predicts stronger validity sensitivity in one-mark conflicts than in equal-count redistributions while preserving adverse-markedness choices at large margins.",
  "predict": "def predict(parameters, state, history):\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            f\"Discrepancy-Evoked Residual Audit expects shape \"\n            f\"(2, n_features); got {stim.shape}.\"\n        )\n\n    a, b = stim[0], stim[1]\n    n_features = stim.shape[1]\n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    if validities.ndim != 1 or validities.size != n_features:\n        raise ValueError(\n            f\"validities length {validities.size} != n_features {n_features}.\"\n        )\n\n    difference = a - b\n    count_difference = float(np.sum(difference))\n    margin = abs(count_difference)\n\n    # A bounded provisional tally prevents the strength of the count signal\n    # from growing without limit as experiments add more features.\n    count_scale = float(parameters[\"count_scale\"])\n    count_signal = float(parameters[\"count_strength\"]) * np.tanh(\n        count_difference / count_scale\n    )\n\n    # Centering cue validity removes the component of weighted evidence that\n    # simply restates which option has more marks. The remaining signal asks\n    # whether an option's marks are carried by unusually reliable experts.\n    centered_validities = validities - float(np.mean(validities))\n    residual_validity = float(np.dot(centered_validities, difference))\n\n    # Validity is always available through baseline_validity_gain. A count\n    # discrepancy evokes an extra audit, maximal at a one-mark margin and\n    # progressively suppressed when the count margin is already decisive.\n    baseline_gain = float(parameters[\"baseline_validity_gain\"])\n    audit_gain = float(parameters[\"audit_gain\"])\n    audit_decay = float(parameters[\"audit_decay\"])\n    if margin > 0.0:\n        discrepancy_activation = margin * np.exp(\n            -audit_decay * max(0.0, margin - 1.0)\n        )\n    else:\n        discrepancy_activation = 0.0\n    validity_gain = baseline_gain + audit_gain * discrepancy_activation\n\n    markedness_evidence = count_signal + validity_gain * residual_validity\n    markedness_evidence *= float(parameters[\"response_precision\"])\n\n    # Positive evidence means A carries the greater adverse burden and hence\n    # favors B. The alternative semantic interpretation reverses all evidence,\n    # and stable polarity confidence mixes the two interpretations.\n    adverse_logits = np.array(\n        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float\n    )\n    adverse_logits -= np.max(adverse_logits)\n    adverse_probs = np.exp(adverse_logits)\n    adverse_probs /= adverse_probs.sum()\n\n    beneficial_probs = adverse_probs[::-1]\n    polarity = float(parameters[\"adverse_polarity_confidence\"])\n    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs\n\n    lapse = float(parameters[\"lapse_rate\"])\n    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        return np.array([0.5, 0.5], dtype=float)\n    return probs / total\n",
  "policy": "def policy(probs):\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    total = float(probs.sum())\n    if not np.isfinite(total) or total <= 0.0:\n        probs = np.ones(len(probs), dtype=np.float64) / len(probs)\n    else:\n        probs /= total\n    return int(np.random.choice(len(probs), p=probs))\n",
  "parameters": {
    "validities": "validities",
    "count_strength": "[2.1, 3.5]",
    "count_scale": "[1.2, 2.0]",
    "baseline_validity_gain": "[0.35, 0.65]",
    "audit_gain": "[1.0, 1.8]",
    "audit_decay": "[0.7, 1.4]",
    "response_precision": "[0.75, 1.4]",
    "adverse_polarity_confidence": "[0.74, 1.0]",
    "lapse_rate": "[0.0, 0.15]"
  },
  "rationale": "The hard gate in pi_3 explains count-dominant choices but necessarily predicts almost no validity slope whenever counts differ, causing its failure in Experiment 5. Uniform smooth integration in pi_4 repairs that slope but applies approximately the same validity gain to equal-count and unequal-count structures, overpredicting Experiment 6. The proposed model instead residualizes validity against count and gives it a structurally conditional gain. Its average one-mark gain is substantially larger than its tie gain, targeting the approximately 0.23 versus 0.11 slope contrast in Experiments 5 and 6. The baseline remains strictly positive, so validity is never excluded. The saturating count signal and decay of discrepancy-evoked auditing protect strong adverse-markedness behavior on large-margin trials, especially Experiment 3, while moderate margins remain noisy enough to fit Experiments 1 and 4. Broad subject-level parameter ranges generate stable heterogeneity in all mechanisms identified by the arbiter rather than relying only on trial-wise choice noise. History is intentionally unused because the task supplies no outcome feedback from which cue meanings or validities could rationally be relearned."
}
```

## Usage

```json
{
  "input_tokens": 13346,
  "output_tokens": 3024
}
```
