# generation_iter_00_attempt_00

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a new theory and its model instantiation in the Heuristic Decision Making domain based on the feedback provided by an arbiter. The feedback contains diagnoses of mechanistic failures of the previous theory along with suggestions for a new theory family that overcomes those failures. The newly proposed theory and model should display human-like behavior when simulated on experiment(s). 
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
- rating_max: Upper bound (inclusive) of each rating value (LLM-proposed; >= 1). Ratings are integers in [0, rating_max].

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
  - `"option_a_ratings"`: List of n_features integer expert ratings (each in [0, rating_max]) for option A on this trial.
  - `"option_b_ratings"`: List of n_features integer expert ratings (each in [0, rating_max]) for option B on this trial.
  - `"response"`: 0 if subject chose A, 1 if subject chose B.
Iterating `for x in history:` iterates the dict KEYS (strings); to walk trials index the lists in lock-step, e.g. `for i in range(len(next(iter(history.values())))): ...`.
- Returns: 1-D `np.ndarray` of choice probabilities over the experiment's discrete action set, summing to 1.

`policy(probs) -> int`:
- Receives the probability vector produced by `predict`.
- Returns: integer index in `[0, len(probs))` identifying the chosen action. If you sample with `np.random.choice(..., p=probs)`, normalise first (`probs = np.asarray(probs, dtype=np.float64); probs /= probs.sum()`) to avoid the "probabilities do not sum to 1" ValueError from float drift.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of integer expert ratings in [0, rating_max]. Every experiment fixes its own feature count (via `validities` length), per-expert validities, and `rating_max`; all three are LLM-proposed. Choosing rating_max=1 gives binary ratings; rating_max>1 gives cardinal ratings whose magnitudes carry information beyond just sign. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` integer expert ratings in [0, rating_max]. The per-feature validities, n_features, and rating_max are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. All three — `n_features`, `validities`, and `rating_max` — are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_5`
- THEORY 2 = `pi_4`
- The recommendation below acts on THEORY 2 (= `pi_4`).

Propose a 'Weighted Additive (WADD)' or 'Linear Integration' theory. Unlike Tallying and Weighted Tallying, which binarize features into strict wins and losses, WADD assumes that decision-makers multiply the full cardinal rating of each feature by its explicit expert validity, summing these products to form an overall value for each option. This will allow the model to capture magnitude-driven trade-offs in experiments with rating_max > 1, providing a strong cardinal competitor to the ordinal/binary mixture model.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_5` (overall score: 0.908)

**Description**
Mixture of Tallying and Weighted Tallying: Decision makers do not universally ignore explicit validities (as in pure Tallying) nor do they perfectly weight every feature by its numerical validity (as in pure Weighted Tallying). Instead, the population consists of a mixture of strategies, or individuals use a blended strategy. Some individuals rely on a simple count of winning features (Tallying), while others incorporate the provided validities to weight those wins. By modeling choice as a convex combination of the Tallying score and the Weighted Tallying score, the model can capture intermediate levels of consensus and account for why human behavior often falls between the predictions of these two pure heuristics.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be (2, n_features)")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Tallying scores: simple count of strictly winning features
    tally_a = np.sum(a > b)
    tally_b = np.sum(b > a)
    
    # Weighted Tallying scores: sum of validities for winning features
    wt_a = np.sum(validities[a > b])
    wt_b = np.sum(validities[b > a])
    
    # Blend the two strategies
    w = float(parameters["w_tally"])
    score_a = w * tally_a + (1.0 - w) * wt_a
    score_b = w * tally_b + (1.0 - w) * wt_b
            
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the blended scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- w_tally: [0.0, 1.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.8000 (var=0.0667) vs this=0.8514 (var=0.0108)
- Experiment 2: real=-0.4000 (var=0.8400) vs this=-0.6950 (var=0.0527)
- Experiment 3: real=0.7467 (var=0.0780) vs this=0.8372 (var=0.0082)
- Experiment 4: real=0.3500 (var=0.0469) vs this=0.2575 (var=0.0042)
- Experiment 5: real=0.7600 (var=0.1824) vs this=0.6783 (var=0.0731)
- Experiment 6: real=0.5000 (var=0.2500) vs this=0.2658 (var=0.0478)
- Experiment 7: real=0.6867 (var=0.1529) vs this=0.7256 (var=0.0291)
- Experiment 8: real=0.6200 (var=0.2356) vs this=0.7800 (var=0.0209)


---

### `pi_4` (overall score: 0.319)

**Description**
Weighted Tallying Heuristic: People make decisions by integrating across multiple features, but rather than treating all cues equally (as in simple Tallying), they weight each feature-wise win by the explicitly provided expert validity. The score for each option is the sum of the validities for the features where that option has a strictly higher rating than the other. The option with the highest validity-weighted tally is chosen. This captures both the tendency to integrate across features and the sensitivity to explicit validities.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Weighted Tallying expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sum validities for features where an option strictly wins
    score_a = np.sum(validities[a > b])
    score_b = np.sum(validities[b > a])
            
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.8000 (var=0.0667) vs this=0.8631 (var=0.0088)
- Experiment 2: real=-0.4000 (var=0.8400) vs this=-0.7633 (var=0.0345)
- Experiment 3: real=0.7467 (var=0.0780) vs this=0.8867 (var=0.0066)
- Experiment 4: real=0.3500 (var=0.0469) vs this=0.2539 (var=0.0038)
- Experiment 5: real=0.7600 (var=0.1824) vs this=0.1858 (var=0.0200)
- Experiment 6: real=0.5000 (var=0.2500) vs this=0.7342 (var=0.0269)
- Experiment 7: real=0.6867 (var=0.1529) vs this=0.3144 (var=0.0099)
- Experiment 8: real=0.6200 (var=0.2356) vs this=0.4926 (var=0.0117)


---

### `pi_2` (overall score: 0.162)

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

    w = np.asarray(parameters["validities"], dtype=float)
    if w.shape[0] != n_features:
        raise ValueError(
            f"validities length {w.shape[0]} != n_features {n_features}."
        )

    # Weighted sum per option (dot product with per-feature weights).
    scores = stim @ w

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
    return int(np.argmax(probabilities))


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: [(0.0, 1.0)] * n_features

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.8000 (var=0.0667) vs this=0.2233 (var=0.0673)
- Experiment 2: real=-0.4000 (var=0.8400) vs this=0.5600 (var=0.6864)
- Experiment 3: real=0.7467 (var=0.0780) vs this=0.2600 (var=0.1057)
- Experiment 4: real=0.3500 (var=0.0469) vs this=0.9567 (var=0.0109)
- Experiment 5: real=0.7600 (var=0.1824) vs this=0.7600 (var=0.1824)
- Experiment 6: real=0.5000 (var=0.2500) vs this=0.2400 (var=0.1824)
- Experiment 7: real=0.6867 (var=0.1529) vs this=0.8333 (var=0.1167)
- Experiment 8: real=0.6200 (var=0.2356) vs this=0.7800 (var=0.1716)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[5, 6, 6, 6]  B=[10, 5, 5, 5]
  A=[2, 8, 8, 8]  B=[9, 7, 7, 7]
  A=[10, 4, 4, 4]  B=[5, 5, 5, 5]
  A=[9, 3, 3, 3]  B=[2, 4, 4, 4]
  A=[6, 6, 6, 2]  B=[5, 5, 5, 9]
  A=[3, 3, 3, 10]  B=[4, 4, 4, 1]
  A=[8, 8, 2, 2]  B=[7, 7, 4, 4]
  A=[2, 2, 8, 8]  B=[4, 4, 7, 7]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    tally_a = np.sum(a_mat > b_mat, axis=1)
    tally_b = np.sum(b_mat > a_mat, axis=1)
    
    mask = tally_a != tally_b
    if not np.any(mask):
        return 0.5
        
    preds = np.where(tally_a > tally_b, 0, 1)
    responses = data['response'].values
    
    accuracy = np.mean(preds[mask] == responses[mask])
    return float(accuracy)

```

**Observed (real) value:** 0.8000 (var=0.0667)
**Other theories' values on this metric (for reference):**
- pi_1: 1.0000 (var=0.0000)
- pi_2: 0.2233 (var=0.0673)
- pi_3: 0.1189 (var=0.0057)
- pi_4: 0.8631 (var=0.0088)
- pi_5: 0.8514 (var=0.0108)

### Experiment 2
**Design**
  A=[0, 4, 4, 4]  B=[5, 3, 3, 3]
  A=[1, 5, 5, 5]  B=[5, 4, 4, 4]
  A=[5, 4, 1, 1]  B=[1, 1, 5, 5]
  A=[5, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[4, 1, 1, 1]  B=[0, 2, 2, 2]
  A=[1, 2, 3, 5]  B=[2, 3, 4, 0]
  A=[5, 1, 1, 1]  B=[1, 2, 2, 2]
  A=[2, 5, 1, 1]  B=[3, 1, 2, 2]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trial 4 (A=[5,0,0,0], sum=5) and trial 1 (A=[0,4,4,4], sum=12)
    a_sum = data['option_a_ratings'].apply(sum)
    chose_a = (data['response'] == 0).astype(float)
    
    mask_t4 = (a_sum == 5)
    mask_t1 = (a_sum == 12)
    
    p_a_t4 = chose_a[mask_t4].mean() if mask_t4.any() else 0.5
    p_a_t1 = chose_a[mask_t1].mean() if mask_t1.any() else 0.5
    
    return float(p_a_t4 - p_a_t1)
```

**Observed (real) value:** -0.4000 (var=0.8400)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5600 (var=0.6864)
- pi_1: -1.0000 (var=0.0000)
- pi_3: 0.7383 (var=0.0522)
- pi_4: -0.7633 (var=0.0345)
- pi_5: -0.6950 (var=0.0527)

### Experiment 3
**Design**
  A=[2, 2, 2, 0]  B=[0, 0, 0, 10]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 8]
  A=[10, 0, 0, 0]  B=[0, 2, 2, 2]
  A=[9, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[5, 5, 0, 0]  B=[0, 0, 5, 6]
  A=[6, 6, 0, 0]  B=[0, 0, 5, 5]
  A=[0, 0, 0, 10]  B=[2, 2, 2, 2]
  A=[2, 2, 2, 0]  B=[0, 0, 0, 9]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    A = np.vstack(data['option_a_ratings'].values)
    B = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(A > B, axis=1)
    b_wins = np.sum(B > A, axis=1)
    
    a_sum = np.sum(A, axis=1)
    b_sum = np.sum(B, axis=1)
    
    tally_pref = np.where(a_wins > b_wins, 0, np.where(b_wins > a_wins, 1, -1))
    ew_pref = np.where(a_sum > b_sum, 0, np.where(b_sum > a_sum, 1, -1))
    
    discordant = (tally_pref != -1) & (ew_pref != -1) & (tally_pref != ew_pref)
    
    if not np.any(discordant):
        return 0.5
        
    responses = data['response'].values
    matches = (responses[discordant] == tally_pref[discordant])
    
    return float(np.mean(matches))
```

**Observed (real) value:** 0.7467 (var=0.0780)
**Other theories' values on this metric (for reference):**
- pi_1: 1.0000 (var=0.0000)
- pi_3: 0.1489 (var=0.0087)
- pi_2: 0.2600 (var=0.1057)
- pi_4: 0.8867 (var=0.0066)
- pi_5: 0.8372 (var=0.0082)

### Experiment 4
**Design**
  A=[10, 2, 2, 2]  B=[0, 3, 3, 3]
  A=[4, 4, 4, 0]  B=[3, 3, 3, 10]
  A=[10, 8, 2, 1]  B=[0, 1, 3, 4]
  A=[1, 1, 0, 0]  B=[0, 0, 10, 10]
  A=[6, 6, 6, 0]  B=[5, 5, 5, 3]
  A=[10, 2, 2, 2]  B=[1, 5, 5, 5]
  A=[0, 0, 0, 10]  B=[1, 1, 1, 0]
  A=[8, 8, 8, 0]  B=[7, 7, 7, 10]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    mask = sum_a != sum_b
    if not mask.any():
        return 0.5
        
    filtered_data = data[mask]
    sum_a_filtered = sum_a[mask]
    sum_b_filtered = sum_b[mask]
    
    eqw_pred = (sum_a_filtered < sum_b_filtered).astype(int)
    matches = (filtered_data['response'] == eqw_pred).mean()
    
    return float(matches)
```

**Observed (real) value:** 0.3500 (var=0.0469)
**Other theories' values on this metric (for reference):**
- pi_3: 0.8767 (var=0.0074)
- pi_1: 0.1667 (var=0.0000)
- pi_2: 0.9567 (var=0.0109)
- pi_4: 0.2539 (var=0.0038)
- pi_5: 0.2575 (var=0.0042)

### Experiment 5
**Design**
  A=[0, 0, 2, 2, 2]  B=[2, 2, 0, 0, 0]
  A=[2, 2, 0, 0, 0]  B=[0, 0, 2, 2, 2]
  A=[2, 0, 2, 0, 0]  B=[0, 2, 0, 2, 0]
  A=[0, 2, 0, 2, 0]  B=[2, 0, 2, 0, 0]
  A=[2, 0, 0, 0, 0]  B=[0, 0, 2, 2, 0]
  A=[0, 0, 2, 2, 0]  B=[2, 0, 0, 0, 0]
  A=[2, 0, 2, 2, 0]  B=[0, 2, 0, 0, 2]
  A=[0, 2, 0, 0, 2]  B=[2, 0, 2, 2, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    tallying_consistent = 0
    total = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == (0, 0, 2, 2, 2) and b == (2, 2, 0, 0, 0):
            if resp == 0:
                tallying_consistent += 1
            total += 1
        elif a == (2, 2, 0, 0, 0) and b == (0, 0, 2, 2, 2):
            if resp == 1:
                tallying_consistent += 1
            total += 1
            
    if total == 0:
        return 0.5
    return tallying_consistent / total
```

**Observed (real) value:** 0.7600 (var=0.1824)
**Other theories' values on this metric (for reference):**
- pi_1: 1.0000 (var=0.0000)
- pi_4: 0.1858 (var=0.0200)
- pi_2: 0.7600 (var=0.1824)
- pi_3: 0.8308 (var=0.0257)
- pi_5: 0.6783 (var=0.0731)

### Experiment 6
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([1.0, 0.8, 0.6, 0.5, 0.5])
    
    A = np.array(data['option_a_ratings'].tolist())
    B = np.array(data['option_b_ratings'].tolist())
    
    wt_a = np.sum(validities * (A > B), axis=1)
    wt_b = np.sum(validities * (B > A), axis=1)
    wt_sign = np.sign(wt_a - wt_b)
    
    tally_a = np.sum(A > B, axis=1)
    tally_b = np.sum(B > A, axis=1)
    tally_sign = np.sign(tally_a - tally_b)
    
    conflict_mask = (wt_sign != 0) & (tally_sign != 0) & (wt_sign != tally_sign)
    
    if not np.any(conflict_mask):
        return 0.5
        
    responses = data['response'].values
    chosen_sign = np.where(responses == 0, 1, -1)
    
    match = (chosen_sign[conflict_mask] == wt_sign[conflict_mask])
    return float(np.mean(match))
```

**Observed (real) value:** 0.5000 (var=0.2500)
**Other theories' values on this metric (for reference):**
- pi_4: 0.7342 (var=0.0269)
- pi_1: 0.0000 (var=0.0000)
- pi_2: 0.2400 (var=0.1824)
- pi_3: 0.1550 (var=0.0153)
- pi_5: 0.2658 (var=0.0478)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    validities = np.array([1.0, 0.8, 0.6, 0.5, 0.5])
    
    a_wins = a_ratings > b_ratings
    b_wins = b_ratings > a_ratings
    
    tally_a = a_wins.sum(axis=1)
    tally_b = b_wins.sum(axis=1)
    
    wt_a = (a_wins * validities).sum(axis=1)
    wt_b = (b_wins * validities).sum(axis=1)
    
    # Identify trials where Tallying strictly prefers A but Weighted Tallying does not
    condition_a = (tally_a > tally_b) & (wt_a <= wt_b)
    # Identify trials where Tallying strictly prefers B but Weighted Tallying does not
    condition_b = (tally_b > tally_a) & (wt_b <= wt_a)
    
    mask = condition_a | condition_b
    if not np.any(mask):
        return 0.0
        
    responses = data['response'].values
    
    # 0 means chose A, 1 means chose B
    match_a = condition_a & (responses == 0)
    match_b = condition_b & (responses == 1)
    
    return float(np.mean((match_a | match_b)[mask]))
```

**Observed (real) value:** 0.6867 (var=0.1529)
**Other theories' values on this metric (for reference):**
- pi_5: 0.7256 (var=0.0291)
- pi_4: 0.3144 (var=0.0099)
- pi_1: 1.0000 (var=0.0000)
- pi_2: 0.8333 (var=0.1167)
- pi_3: 0.8889 (var=0.0073)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify Trial 1 where WT predicts a perfect tie (score A = 1.0, score B = 0.5 + 0.5 = 1.0)
    # but Tallying prefers B (1 win vs 2 wins).
    mask = (data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 0, 0))) & \
           (data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 0, 1, 1)))
    if mask.sum() == 0:
        return 0.5
    # Return the proportion of times B was chosen
    return float(data[mask]['response'].mean())
```

**Observed (real) value:** 0.6200 (var=0.2356)
**Other theories' values on this metric (for reference):**
- pi_4: 0.4926 (var=0.0117)
- pi_5: 0.7800 (var=0.0209)
- pi_1: 1.0000 (var=0.0000)
- pi_2: 0.7800 (var=0.1716)
- pi_3: 0.8632 (var=0.0133)


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
```json
{
  "theory": "Weighted Additive (WADD) Model: Decision-makers evaluate options by multiplying the full cardinal rating of each feature by its explicitly provided expert validity, and then summing these products to form an overall expected value for each option. Unlike tallying heuristics that binarize feature differences into strict wins and losses, WADD integrates both the magnitude of the feature ratings and the explicit cue weights. This compensatory strategy allows a large advantage on a lower-validity feature to outweigh a small deficit on a higher-validity feature. Choices are made probabilistically via a softmax over the integrated values, combined with a uniform lapse rate.",
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n    \n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\"Stimulus must be (2, n_features)\")\n        \n    a, b = stim[0], stim[1]\n    # Use the explicitly provided expert validities from the experiment\n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    \n    # WADD score: sum of (cardinal rating * explicit validity)\n    score_a = np.sum(a * validities)\n    score_b = np.sum(b * validities)\n            \n    scores = np.array([score_a, score_b])\n    \n    beta = float(parameters[\"beta\"])\n    epsilon = float(parameters[\"epsilon\"])\n    \n    # Softmax over the integrated scores\n    z = beta * (scores - np.max(scores))\n    e = np.exp(z)\n    p_core = e / np.sum(e)\n    \n    n_opts = p_core.shape[0]\n    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)\n",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs /= probs.sum()\n    return int(np.random.choice(len(probs), p=probs))\n",
  "parameters": {
    "beta": "[0.1, 20.0]",
    "epsilon": "[0.0, 0.5]",
    "validities": "validities"
  },
  "rationale": "Following the arbiter's recommendation, this theory instantiates the Weighted Additive (WADD) model. A previous attempt at WADD (`pi_2`) failed because it treated validities as free parameters to be fitted per-subject (`[(0.0, 1.0)] * n_features`), completely ignoring the explicit expert validities provided in the experiment. By correctly anchoring the weights to the explicit validities (`validities: validities`), this model accurately captures how decision-makers integrate cardinal feature magnitudes with explicit cue weights, providing a robust compensatory benchmark that accounts for magnitude-driven trade-offs."
}
```
```

## Usage

```json
{
  "prompt_token_count": 11185,
  "candidates_token_count": 713,
  "total_token_count": 13511
}
```
