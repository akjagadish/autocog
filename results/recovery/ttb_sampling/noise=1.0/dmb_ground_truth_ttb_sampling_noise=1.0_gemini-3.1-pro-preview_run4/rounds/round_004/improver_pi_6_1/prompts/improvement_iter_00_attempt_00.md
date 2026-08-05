# improvement_iter_00_attempt_00

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a NEW model instantiation of an EXISTING theory, given arbiter feedback on the previous instantiation. The theory's prose claim is fixed — you are NOT redefining the theory. You are regenerating only the runnable bits: the `predict` function, the `policy` function, and the `parameters` ranges. The newly proposed model should display human-like behavior when simulated on experiments in the Decision Making (Binary Features) domain.

The goal of the model improvement process is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across multiple experiments. 
If your model fails to compile or behaves badly, you may receive feedback and have to propose another instantiation. Iterate until accepted.

If you think the failure to capture human behavior is due to arbiter feedback that is inaccurate or unhelpful, you can propose a new model instance that ignores the feedback, but you must provide rationale for why you are ignoring it and how your proposal overcomes the identified mechanistic failures.

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

## ROUND THEORIES
The arbiter compared the two theories below this round. Your job is to regenerate ONLY the runnable bits (`predict`, `policy`, `parameters`) of the one tagged **TO REVISE**, keeping its description verbatim. The other theory is shown for context — it is NOT being changed.

### THEORY 1 — `pi_4` (other theory — context only, NOT revised)

**Description:**
Random Guessing: Due to task complexity, lack of trial-by-trial correctness feedback, or low motivation, subjects do not systematically evaluate the options using the provided validities or features. Instead, they make uniformly random choices on every trial.

**Model instance (shown for context):**

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    return np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
(none)

---

### THEORY 2 — `pi_6` **TO REVISE**

**Description (PRESERVE VERBATIM — do not rewrite the prose):**
Spatial Bias / Option Preference: Subjects completely ignore the complex feature information provided on each trial. Instead, their choices are driven by an idiosyncratic, subject-level baseline preference for Option A versus Option B (e.g., a left/right spatial bias or an order effect). Each subject has a fixed probability of choosing Option A on any given trial, which varies between subjects but remains constant across trials for a given subject. This explains why choices are invariant to feature differences while accounting for individual differences in baseline choice rates.

**Previous model instance — REGENERATE `predict`, `policy`, and `parameters` ranges:**

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    p_a = float(parameters["bias_A"])
    return np.array([p_a, 1.0 - p_a])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- bias_A: [0.3, 0.7]


## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_4`
- THEORY 2 = `pi_6`
- The recommendation below acts on THEORY 2 (= `pi_6`).

Preserve the theory description but update the parameter ranges for `bias_A`. The current implementation likely samples `bias_A` from a wide uniform distribution (e.g., [0.0, 1.0] or [0.2, 0.8]), which overestimates the between-subject variance in choice proportions. Constrain the parameter range to a tightly bounded distribution around 0.5 (e.g., Uniform(0.4, 0.6) or a Beta distribution with high concentration around 0.5). This will allow the model to capture the slight overdispersion in subject choice proportions (around 0.0047) without overpredicting it.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_5` (overall score: 0.724)

**Description**
Random Feature Heuristic (Minimalist): Subjects do not integrate multiple features or weight them by validity. Instead, on each trial, they randomly sample exactly one feature uniformly at random. They choose the option with the higher value on that sampled feature. If the options tie on that feature, they guess randomly. This acts as a highly noisy but boundedly rational alternative to pure guessing, predicting choices that slightly favor the option with more positive features overall. A lapse rate (epsilon) accounts for additional purely random choices.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    a, b = stim[0], stim[1]
    n_features = len(a)
    
    # The marginal probability of choosing A when picking one feature at random:
    # P(A) = 1/n * sum(a_i > b_i) + 0.5/n * sum(a_i == b_i)
    # For binary features, this simplifies exactly to 0.5 + 0.5 * (sum(a) - sum(b)) / n
    diff = np.sum(a) - np.sum(b)
    p_a_core = 0.5 + 0.5 * diff / n_features
    p_b_core = 1.0 - p_a_core
    
    epsilon = float(parameters["epsilon"])
    p_a = (1.0 - epsilon) * p_a_core + epsilon * 0.5
    p_b = (1.0 - epsilon) * p_b_core + epsilon * 0.5
    
    return np.array([p_a, p_b])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- epsilon: [0.0, 1.0]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4844 (var=0.0167) vs this=0.4778 (var=0.0357)
- Experiment 2: real=0.4800 (var=0.0103) vs this=0.4625 (var=0.0074)
- Experiment 3: real=0.4954 (var=0.0018) vs this=0.4269 (var=0.0036)
- Experiment 4: real=0.5046 (var=0.0028) vs this=0.5673 (var=0.0040)
- Experiment 5: real=0.0015 (var=0.0001) vs this=0.0141 (var=0.0005)
- Experiment 6: real=0.5040 (var=0.0025) vs this=0.5870 (var=0.0039)
- Experiment 7: real=0.5006 (var=0.0047) vs this=0.6925 (var=0.0126)
- Experiment 8: real=0.0112 (var=0.0080) vs this=0.2624 (var=0.0308)
- Experiment 9: real=0.0018 (var=0.0000) vs this=0.0025 (var=0.0000)
- Experiment 10: real=0.0047 (var=0.0000) vs this=0.0026 (var=0.0000)


---

### `pi_2` (overall score: 0.337)

**Description**
People compare two options by computing, for each option, a weighted sum of its feature values, where each feature is weighted by its subjective validity (or importance). The option with the higher weighted sum is chosen. WADD is the compensatory benchmark against which one-reason heuristics like Take The Best are contrasted: a large deficit on a high-validity cue can be compensated by a sufficiently strong advantage on lower-validity cues, so no single feature is ever decisive on its own. Unlike Tallying, WADD uses cardinal feature magnitudes and weights them by validity, so it exploits both the sign and the size of each feature-wise comparison as well as inter-cue differences in informativeness. Unlike Equal-Weight, weights differ across features. Behavior is invariant to a shared affine rescaling across options but scales linearly with per-feature weight. When the two weighted sums are equal the model has no basis for preference and the learner must guess. Response noise enters through a softmax over the two weighted sums with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Weighted Additive rule (Payne, Bettman & Johnson
    # 1993). Stimulus is the pair of option feature vectors for the
    # current trial: array-like of shape (2, n_features), row 0 =
    # option A, row 1 = option B. Each option's score is the dot
    # product of its feature vector with the (subjective) validity
    # weights. History is ignored: the choice depends only on the
    # current stimulus.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    validities = np.asarray(parameters["validities"], dtype=float)
    w = np.asarray(parameters["weights"], dtype=float)
    if w.shape[0] != n_features:
        raise ValueError(
            f"weights length {w.shape[0]} != n_features {n_features}."
        )

    # Weighted sum per option (dot product with per-feature weights).
    scores = stim @ (validities * w)

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Uniform lapse blended into the softmax (standard choice-with-lapse
    # formulation; epsilon=0.5 yields equiprobable options, matching
    # the paper's maximum-noise condition).
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
- weights: [(0.0, 1.0)] * n_features

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4844 (var=0.0167) vs this=0.5311 (var=0.0885)
- Experiment 2: real=0.4800 (var=0.0103) vs this=0.5550 (var=0.0973)
- Experiment 3: real=0.4954 (var=0.0018) vs this=0.3573 (var=0.0093)
- Experiment 4: real=0.5046 (var=0.0028) vs this=0.7226 (var=0.0183)
- Experiment 5: real=0.0015 (var=0.0001) vs this=0.0480 (var=0.0032)
- Experiment 6: real=0.5040 (var=0.0025) vs this=0.6903 (var=0.0073)
- Experiment 7: real=0.5006 (var=0.0047) vs this=0.8842 (var=0.0070)
- Experiment 8: real=0.0112 (var=0.0080) vs this=0.5498 (var=0.0445)
- Experiment 9: real=0.0018 (var=0.0000) vs this=0.0012 (var=0.0000)
- Experiment 10: real=0.0047 (var=0.0000) vs this=0.0023 (var=0.0000)


---

### `pi_3` (overall score: 0.235)

**Description**
Take The Best (TTB) heuristic: People make decisions by searching through features in descending order of their validities. They stop at the first feature that discriminates between the two options and choose the option with the positive value on that feature. If no feature discriminates, they guess randomly. Response noise is incorporated via a lapse rate (epsilon) that can range up to 1.0, allowing for fully random guessing.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort features by validity in descending order
    order = np.argsort(-validities)
    
    p_core = np.array([0.5, 0.5])
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)

`parameters`:
- epsilon: [0.0, 1.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4844 (var=0.0167) vs this=0.7689 (var=0.0409)
- Experiment 2: real=0.4800 (var=0.0103) vs this=0.7592 (var=0.0265)
- Experiment 3: real=0.4954 (var=0.0018) vs this=0.7612 (var=0.0230)
- Experiment 4: real=0.5046 (var=0.0028) vs this=0.3204 (var=0.0117)
- Experiment 5: real=0.0015 (var=0.0001) vs this=0.0630 (var=0.0052)
- Experiment 6: real=0.5040 (var=0.0025) vs this=0.5450 (var=0.0028)
- Experiment 7: real=0.5006 (var=0.0047) vs this=0.7439 (var=0.0196)
- Experiment 8: real=0.0112 (var=0.0080) vs this=0.0650 (var=0.0058)
- Experiment 9: real=0.0018 (var=0.0000) vs this=0.0012 (var=0.0000)
- Experiment 10: real=0.0047 (var=0.0000) vs this=0.0025 (var=0.0000)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[0, 1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_ratings = data['option_a_ratings'].apply(tuple)
    b_ratings = data['option_b_ratings'].apply(tuple)
    
    mask1 = (a_ratings == (0, 0, 0, 1, 1, 1)) & (b_ratings == (1, 1, 0, 0, 0, 0))
    mask2 = (a_ratings == (1, 1, 0, 0, 0, 0)) & (b_ratings == (0, 0, 0, 1, 1, 1))
    
    resp = []
    if mask1.any():
        resp.extend(data.loc[mask1, 'response'].tolist())
    if mask2.any():
        resp.extend((1 - data.loc[mask2, 'response']).tolist())
        
    if len(resp) == 0:
        return 0.5
    return float(np.mean(resp))
```

**Observed (real) value:** 0.4844 (var=0.0167)
**Other theories' values on this metric (for reference):**
- pi_1: 0.1533 (var=0.0291)
- pi_2: 0.5311 (var=0.0885)
- pi_3: 0.7689 (var=0.0409)
- pi_4: 0.4867 (var=0.0202)
- pi_5: 0.4778 (var=0.0357)
- pi_6: 0.5200 (var=0.0565)

### Experiment 2
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    a_tuples = data['option_a_ratings'].apply(tuple)
    b_tuples = data['option_b_ratings'].apply(tuple)
    
    is_t1 = (a_tuples == (1, 1, 0, 0, 0)) & (b_tuples == (0, 0, 1, 1, 1))
    is_t2 = (a_tuples == (0, 0, 1, 1, 1)) & (b_tuples == (1, 1, 0, 0, 0))
    
    wadd_consistent = (is_t1 & (data['response'] == 0)) | (is_t2 & (data['response'] == 1))
    mask = is_t1 | is_t2
    
    if mask.sum() == 0:
        return 0.5
    return float(wadd_consistent.sum() / mask.sum())
```

**Observed (real) value:** 0.4800 (var=0.0103)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5550 (var=0.0973)
- pi_1: 0.1492 (var=0.0174)
- pi_3: 0.7592 (var=0.0265)
- pi_4: 0.5150 (var=0.0123)
- pi_5: 0.4625 (var=0.0074)
- pi_6: 0.5000 (var=0.0078)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_pred = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred is not None:
            matches.append(1.0 if ttb_pred == resp else 0.0)
            
    return float(np.mean(matches)) if len(matches) > 0 else 0.5
```

**Observed (real) value:** 0.4954 (var=0.0018)
**Other theories' values on this metric (for reference):**
- pi_3: 0.7612 (var=0.0230)
- pi_2: 0.3573 (var=0.0093)
- pi_1: 0.3190 (var=0.0029)
- pi_4: 0.5096 (var=0.0020)
- pi_5: 0.4269 (var=0.0036)
- pi_6: 0.4898 (var=0.0029)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_sums = data['option_a_ratings'].apply(np.sum)
    b_sums = data['option_b_ratings'].apply(np.sum)
    wadd_choice = (b_sums > a_sums).astype(int)
    return float((data['response'] == wadd_choice).mean())
```

**Observed (real) value:** 0.5046 (var=0.0028)
**Other theories' values on this metric (for reference):**
- pi_2: 0.7226 (var=0.0183)
- pi_3: 0.3204 (var=0.0117)
- pi_1: 0.8270 (var=0.0101)
- pi_4: 0.5193 (var=0.0019)
- pi_5: 0.5673 (var=0.0040)
- pi_6: 0.5035 (var=0.0032)

### Experiment 5
**Design**
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    keys = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x))) + '_' + data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    means = data.groupby(keys)['response'].mean()
    return float(np.var(means))
```

**Observed (real) value:** 0.0015 (var=0.0001)
**Other theories' values on this metric (for reference):**
- pi_4: 0.0003 (var=0.0001)
- pi_2: 0.0480 (var=0.0032)
- pi_1: 0.0547 (var=0.0005)
- pi_3: 0.0630 (var=0.0052)
- pi_5: 0.0141 (var=0.0005)
- pi_6: 0.0005 (var=0.0001)

### Experiment 6
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = np.array([0.95, 0.8, 0.75, 0.6, 0.5])
    
    matches = 0
    total = 0
    
    for _, row in data.iterrows():
        a_ratings = np.array(row['option_a_ratings'])
        b_ratings = np.array(row['option_b_ratings'])
        
        score_a = np.dot(a_ratings, validities)
        score_b = np.dot(b_ratings, validities)
        
        if abs(score_a - score_b) > 1e-5:
            predicted_response = 0 if score_a > score_b else 1
            if row['response'] == predicted_response:
                matches += 1
            total += 1
            
    return matches / total if total > 0 else 0.5
```

**Observed (real) value:** 0.5040 (var=0.0025)
**Other theories' values on this metric (for reference):**
- pi_2: 0.6903 (var=0.0073)
- pi_4: 0.5040 (var=0.0025)
- pi_1: 0.8552 (var=0.0091)
- pi_3: 0.5450 (var=0.0028)
- pi_5: 0.5870 (var=0.0039)
- pi_6: 0.4943 (var=0.0029)

### Experiment 7
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    mask = sum_a != sum_b
    if not mask.any():
        return 0.5
        
    responses = data.loc[mask, 'response']
    a_more = sum_a[mask] > sum_b[mask]
    
    chose_max = ((responses == 0) & a_more) | ((responses == 1) & ~a_more)
    return float(chose_max.mean())
```

**Observed (real) value:** 0.5006 (var=0.0047)
**Other theories' values on this metric (for reference):**
- pi_4: 0.4986 (var=0.0024)
- pi_5: 0.6925 (var=0.0126)
- pi_1: 0.8772 (var=0.0059)
- pi_2: 0.8842 (var=0.0070)
- pi_3: 0.7439 (var=0.0196)
- pi_6: 0.4978 (var=0.0036)

### Experiment 8
**Design**
  A=[1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    diff = sum_a - sum_b
    
    chose_a = 1 - data['response']
    
    pos_mean = chose_a[diff > 0].mean()
    neg_mean = chose_a[diff < 0].mean()
    
    if pd.isna(pos_mean) or pd.isna(neg_mean):
        return 0.0
        
    return float(pos_mean - neg_mean)
```

**Observed (real) value:** 0.0112 (var=0.0080)
**Other theories' values on this metric (for reference):**
- pi_5: 0.2624 (var=0.0308)
- pi_4: 0.0206 (var=0.0141)
- pi_1: 0.7520 (var=0.0341)
- pi_2: 0.5498 (var=0.0445)
- pi_3: 0.0650 (var=0.0058)
- pi_6: -0.0106 (var=0.0084)

### Experiment 9
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    subject_means = data.groupby('subject_id')['response'].mean()
    sq_devs = (subject_means - 0.5) ** 2
    return float(sq_devs.mean())
```

**Observed (real) value:** 0.0018 (var=0.0000)
**Other theories' values on this metric (for reference):**
- pi_4: 0.0027 (var=0.0000)
- pi_6: 0.0180 (var=0.0002)
- pi_1: 0.0010 (var=0.0000)
- pi_2: 0.0012 (var=0.0000)
- pi_3: 0.0012 (var=0.0000)
- pi_5: 0.0025 (var=0.0000)

### Experiment 10
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    subject_means = data.groupby('subject_id')['response'].mean()
    return float(((subject_means - 0.5) ** 2).mean())
```

**Observed (real) value:** 0.0047 (var=0.0000)
**Other theories' values on this metric (for reference):**
- pi_6: 0.0195 (var=0.0003)
- pi_4: 0.0025 (var=0.0000)
- pi_1: 0.0023 (var=0.0000)
- pi_2: 0.0023 (var=0.0000)
- pi_3: 0.0025 (var=0.0000)
- pi_5: 0.0026 (var=0.0000)


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL
Propose a new model instance for the theory above from scratch. Keep the theory's prose claim implicit but unchanged — your only job is to regenerate `predict`, `policy`, and the `parameters` ranges so that the implementation actually displays the behavior the theory claims, while faithfully implementing the mechanism family the arbiter prescribed.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- predict: Python source defining def predict(parameters, state, history) -> np.ndarray.
- policy: Python source defining def policy(probs) -> int.
- parameters: Parameter ranges (e.g. "[1.0, 10.0]") or choices (e.g. "{1, 2}"), sampled per subject.
- rationale: Reasoning behind this model design; used to explain why this model is better then the previous ones.


## Response

```json
```json
{
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n    p_a = float(parameters[\"bias_A\"])\n    return np.array([p_a, 1.0 - p_a])",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs /= probs.sum()\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "bias_A": "[0.4, 0.6]"
  },
  "rationale": "Following the arbiter's recommendation, we restrict the range of `bias_A` from a wider distribution to a tightly bounded Uniform(0.4, 0.6). The variance of a Uniform(0.4, 0.6) distribution is approximately 0.0033, which closely matches the slight overdispersion in subject choice proportions observed in Experiments 9 and 10 (0.0018 to 0.0047). This allows the model to capture individual differences in baseline choice rates without overpredicting the between-subject variance."
}
```
```

## Usage

```json
{
  "prompt_token_count": 13235,
  "candidates_token_count": 286,
  "total_token_count": 14018
}
```
