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
- THEORY 1 = `pi_6`
- THEORY 2 = `pi_2`
- The recommendation below acts on THEORY 1 (= `pi_6`).

Propose a new theory to replace the TTB+Tallying mixture. The new theory should account for the fact that subjects largely rely on counting wins (Tallying), which leads to guessing on tied trials (as seen in Exp 1 and 2), but they are also sensitive to cue validities in extreme compensatory cases (as seen in Exp 8). A potential candidate is a 'Thresholded Weighted Additive' model, where subjects integrate cues using validities but only perceive a difference if the weighted sum exceeds a certain threshold; otherwise, they fall back to a simple tally or guess. Alternatively, a 'Tallying with Validity-Based Attention' model, where cues are tallied but the probability of considering a cue depends on its validity.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_2` (overall score: 0.524)

**Description**
People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Tallying heuristic (Dawes 1979; Gigerenzer &
    # Goldstein 1999). Stimulus is the pair of option feature vectors
    # for the current trial: array-like of shape (2, n_features),
    # with row 0 = option A, row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    # Count strict feature-wise wins; ties contribute to neither option.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. When
    # a_wins == b_wins the softmax is exactly uniform regardless of
    # beta, which is the correct behavior for an undiscriminating
    # tally.
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

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2775 (var=0.0072) vs this=0.1317 (var=0.0087)
- Experiment 2: real=0.8178 (var=0.0246) vs this=0.8661 (var=0.0073)
- Experiment 3: real=0.1400 (var=0.0117) vs this=0.1208 (var=0.0082)
- Experiment 4: real=0.8354 (var=0.0165) vs this=0.8846 (var=0.0107)
- Experiment 5: real=0.2194 (var=0.0145) vs this=0.2118 (var=0.0086)
- Experiment 6: real=0.6650 (var=0.0076) vs this=0.1683 (var=0.0128)
- Experiment 7: real=-0.3850 (var=0.0268) vs this=-0.0225 (var=0.0134)
- Experiment 8: real=0.2700 (var=0.0052) vs this=0.1000 (var=0.0028)
- Experiment 9: real=0.4567 (var=0.0102) vs this=0.5092 (var=0.0104)
- Experiment 10: real=0.4967 (var=0.0079) vs this=0.5089 (var=0.0065)


---

### `pi_6` (overall score: 0.519)

**Description**
Decision-makers use a discrete mixture of two distinct heuristics: Take-The-Best (TTB) and Tallying. Rather than integrating all information via a continuous weighted sum, a subject either relies entirely on the single most valid discriminating cue (TTB) or ignores cue validities to simply count the number of winning features for each option (Tallying). The probability of using TTB versus Tallying is governed by a mixing parameter. Both heuristic outputs are softened by independent temperature parameters (beta_ttb and beta_tally) to account for decision noise and differing scales of score differences between the two strategies, preventing brittle deterministic predictions.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be of shape (2, n_features).")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    p_ttb = float(parameters["p_ttb"])
    beta_ttb = float(parameters["beta_ttb"])
    beta_tally = float(parameters["beta_tally"])
    epsilon = float(parameters["epsilon"])
    
    # --- Take-The-Best (TTB) Prediction ---
    # Sort cues by validity in descending order
    cue_order = np.argsort(val)[::-1]
    
    ttb_scores = np.array([0.0, 0.0])
    for idx in cue_order:
        if a[idx] > b[idx]:
            ttb_scores = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            ttb_scores = np.array([0.0, 1.0])
            break
            
    # Softmax over TTB scores
    z_ttb = beta_ttb * (ttb_scores - np.max(ttb_scores))
    e_ttb = np.exp(z_ttb)
    ttb_probs = e_ttb / np.sum(e_ttb)
            
    # --- Tallying Prediction ---
    # Count strict feature-wise wins
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])
    
    # Softmax over tally scores
    z = beta_tally * (scores - np.max(scores))
    e = np.exp(z)
    tally_probs = e / np.sum(e)
    
    # --- Mixture and Lapse ---
    # Mix the two strategies
    mixed_probs = p_ttb * ttb_probs + (1.0 - p_ttb) * tally_probs
    
    # Apply random lapse
    final_probs = (1.0 - epsilon) * mixed_probs + epsilon * np.array([0.5, 0.5])
    
    return final_probs


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=float)
    probs /= np.sum(probs)
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- p_ttb: [0.0, 1.0]
- beta_ttb: [0.1, 20.0]
- beta_tally: [0.1, 20.0]
- epsilon: [0.0, 0.1]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2775 (var=0.0072) vs this=0.4808 (var=0.0767)
- Experiment 2: real=0.8178 (var=0.0246) vs this=0.4678 (var=0.0757)
- Experiment 3: real=0.1400 (var=0.0117) vs this=0.4733 (var=0.0831)
- Experiment 4: real=0.8354 (var=0.0165) vs this=0.4185 (var=0.0717)
- Experiment 5: real=0.2194 (var=0.0145) vs this=0.5360 (var=0.0674)
- Experiment 6: real=0.6650 (var=0.0076) vs this=0.5229 (var=0.0634)
- Experiment 7: real=-0.3850 (var=0.0268) vs this=0.0212 (var=0.0117)
- Experiment 8: real=0.2700 (var=0.0052) vs this=0.2506 (var=0.0179)
- Experiment 9: real=0.4567 (var=0.0102) vs this=0.6608 (var=0.0220)
- Experiment 10: real=0.4967 (var=0.0079) vs this=0.7306 (var=0.0169)


---

### `pi_5` (overall score: 0.404)

**Description**
People make decisions by computing a weighted sum of the features for each option, but the weights are non-linear transformations of the provided cue validities. Specifically, subjects exponentiate the validities by a parameter gamma, which allows the strategy to continuously interpolate between Tallying (gamma = 0) and Take-The-Best (gamma -> infinity). The option with the higher total weighted score is preferred, subject to decision noise (softmax) and occasional lapses.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    weights = val ** gamma
    
    # Compute weighted sum of features for each option
    a_score = np.dot(a, weights)
    b_score = np.dot(b, weights)
    scores = np.array([a_score, b_score])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=float)
    probs /= np.sum(probs)
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.2]
- gamma: [-1.0, 2.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2775 (var=0.0072) vs this=0.0663 (var=0.0053)
- Experiment 2: real=0.8178 (var=0.0246) vs this=0.9144 (var=0.0107)
- Experiment 3: real=0.1400 (var=0.0117) vs this=0.4292 (var=0.1526)
- Experiment 4: real=0.8354 (var=0.0165) vs this=0.6008 (var=0.1490)
- Experiment 5: real=0.2194 (var=0.0145) vs this=0.2126 (var=0.0077)
- Experiment 6: real=0.6650 (var=0.0076) vs this=0.0592 (var=0.0036)
- Experiment 7: real=-0.3850 (var=0.0268) vs this=0.3150 (var=0.1278)
- Experiment 8: real=0.2700 (var=0.0052) vs this=0.1906 (var=0.0093)
- Experiment 9: real=0.4567 (var=0.0102) vs this=0.5400 (var=0.0142)
- Experiment 10: real=0.4967 (var=0.0079) vs this=0.5872 (var=0.0559)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    match_ttb = 0
    total = 0
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # TTB prediction: first discriminating cue
        ttb_winner = None
        for j in range(len(a)):
            if a[j] > b[j]:
                ttb_winner = 0
                break
            elif b[j] > a[j]:
                ttb_winner = 1
                break
                
        # Tallying prediction: majority of discriminating cues
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = None
            
        # Only consider trials where the two heuristics deterministically disagree
        if ttb_winner is not None and tally_winner is not None and ttb_winner != tally_winner:
            if row['response'] == ttb_winner:
                match_ttb += 1
            total += 1
            
    if total == 0:
        return 0.5
    return match_ttb / total
```

**Observed (real) value:** 0.2775 (var=0.0072)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8433 (var=0.0143)
- pi_2: 0.1317 (var=0.0087)
- pi_3: 0.1437 (var=0.0120)
- pi_4: 0.8688 (var=0.0108)
- pi_5: 0.0663 (var=0.0053)
- pi_6: 0.4808 (var=0.0767)

### Experiment 2
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 0]
  A=[0, 0, 1, 0]  B=[0, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 1, 0]  B=[0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    tally_match = 0
    total = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        if a_wins != b_wins:
            tally_pref = 0 if a_wins > b_wins else 1
            if row['response'] == tally_pref:
                tally_match += 1
            total += 1
            
    return float(tally_match / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.8178 (var=0.0246)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8661 (var=0.0073)
- pi_1: 0.1822 (var=0.0123)
- pi_3: 0.8550 (var=0.0087)
- pi_4: 0.1433 (var=0.0089)
- pi_5: 0.9144 (var=0.0107)
- pi_6: 0.4678 (var=0.0757)

### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    wadd_consistent = 0
    total = 0
    for _, row in data.iterrows():
        a_sum = sum(row['option_a_ratings'])
        b_sum = sum(row['option_b_ratings'])
        if a_sum == 2 and b_sum == 3:
            if row['response'] == 0:
                wadd_consistent += 1
            total += 1
        elif a_sum == 3 and b_sum == 2:
            if row['response'] == 1:
                wadd_consistent += 1
            total += 1
    if total == 0:
        return 0.5
    return wadd_consistent / total
```

**Observed (real) value:** 0.1400 (var=0.0117)
**Other theories' values on this metric (for reference):**
- pi_3: 0.7250 (var=0.0197)
- pi_2: 0.1208 (var=0.0082)
- pi_1: 0.8558 (var=0.0144)
- pi_4: 0.8483 (var=0.0104)
- pi_5: 0.4292 (var=0.1526)
- pi_6: 0.4733 (var=0.0831)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    A_t1 = [0, 0, 1, 1, 1]
    B_t1 = [1, 1, 0, 0, 0]
    A_t2 = [1, 1, 0, 0, 0]
    B_t2 = [0, 0, 1, 1, 1]
    
    consistencies = []
    
    for _, row in data.iterrows():
        a = list(row['option_a_ratings'])
        b = list(row['option_b_ratings'])
        r = row['response']
        
        # Trial 1: Tallying prefers A (3 wins vs 2), WADD prefers B (1.90 vs 1.65)
        if a == A_t1 and b == B_t1:
            consistencies.append(1 if r == 0 else 0)
        # Trial 2: Tallying prefers B (3 wins vs 2), WADD prefers A (1.90 vs 1.65)
        elif a == A_t2 and b == B_t2:
            consistencies.append(1 if r == 1 else 0)
            
    if not consistencies:
        return 0.5
    return float(np.mean(consistencies))
```

**Observed (real) value:** 0.8354 (var=0.0165)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8846 (var=0.0107)
- pi_3: 0.2362 (var=0.0189)
- pi_1: 0.1662 (var=0.0144)
- pi_4: 0.1338 (var=0.0124)
- pi_5: 0.6008 (var=0.1490)
- pi_6: 0.4185 (var=0.0717)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    matches = 0
    total = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        for i in range(len(a)):
            if a[i] > b[i]:
                if resp == 0:
                    matches += 1
                total += 1
                break
            elif b[i] > a[i]:
                if resp == 1:
                    matches += 1
                total += 1
                break
    return float(matches / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.2194 (var=0.0145)
**Other theories' values on this metric (for reference):**
- pi_4: 0.8615 (var=0.0113)
- pi_2: 0.2118 (var=0.0086)
- pi_1: 0.8522 (var=0.0069)
- pi_3: 0.2777 (var=0.0039)
- pi_5: 0.2126 (var=0.0077)
- pi_6: 0.5360 (var=0.0674)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Extract the highest validity feature (feature 0) for both options
    a0 = data['option_a_ratings'].apply(lambda x: x[0])
    b0 = data['option_b_ratings'].apply(lambda x: x[0])
    
    # Calculate the total number of feature-wise wins for each option
    a_wins = data.apply(lambda row: sum(a > b for a, b in zip(row['option_a_ratings'], row['option_b_ratings'])), axis=1)
    b_wins = data.apply(lambda row: sum(b > a for a, b in zip(row['option_a_ratings'], row['option_b_ratings'])), axis=1)
    
    # Identify critical trials where the option favored by the most valid cue (feature 0) 
    # is actually the option with FEWER total winning features.
    # This perfectly dissociates Take The Best (which follows feature 0) 
    # from Tallying (which follows the total number of wins).
    critical = ((a0 == 1) & (a_wins < b_wins)) | ((b0 == 1) & (b_wins < a_wins))
    
    if not critical.any():
        return 0.5
        
    crit_data = data[critical]
    
    # The choice predicted by TTB is exactly the option that has a 1 on feature 0.
    # Since feature 0 always discriminates in this design, B[0] == 1 means TTB chooses B (1),
    # and B[0] == 0 means TTB chooses A (0).
    ttb_choice = crit_data['option_b_ratings'].apply(lambda x: x[0])
    
    # Return the proportion of times the subject's response matches the TTB prediction on these critical trials.
    # TTB will score near 1.0, while Tallying will score near 0.0.
    return float((crit_data['response'] == ttb_choice).mean())
```

**Observed (real) value:** 0.6650 (var=0.0076)
**Other theories' values on this metric (for reference):**
- pi_2: 0.1683 (var=0.0128)
- pi_4: 0.8275 (var=0.0143)
- pi_1: 0.8538 (var=0.0135)
- pi_3: 0.1700 (var=0.0140)
- pi_5: 0.0592 (var=0.0036)
- pi_6: 0.5229 (var=0.0634)

### Experiment 7
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Convert lists to strings for hashable comparison
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    
    # Trial 1: A=[1, 1, 0, 0, 0], B=[0, 0, 1, 1, 1]
    t1_mask = (a_str == '11000') & (b_str == '00111')
    # Trial 2: A=[1, 0, 0, 0, 0], B=[0, 1, 1, 0, 0]
    t2_mask = (a_str == '10000') & (b_str == '01100')
    
    # Response 0 means option A was chosen
    p_a_t1 = (data[t1_mask]['response'] == 0).mean()
    p_a_t2 = (data[t2_mask]['response'] == 0).mean()
    
    if pd.isna(p_a_t1): p_a_t1 = 0.0
    if pd.isna(p_a_t2): p_a_t2 = 0.0
    
    return float(p_a_t1 - p_a_t2)
```

**Observed (real) value:** -0.3850 (var=0.0268)
**Other theories' values on this metric (for reference):**
- pi_5: 0.3150 (var=0.1278)
- pi_2: -0.0225 (var=0.0134)
- pi_1: 0.0188 (var=0.0125)
- pi_3: 0.0888 (var=0.0156)
- pi_4: 0.0275 (var=0.0174)
- pi_6: 0.0212 (var=0.0117)

### Experiment 8
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    a_keys = data['option_a_ratings'].apply(tuple)
    b_keys = data['option_b_ratings'].apply(tuple)
    
    # Identify "tie" trials where Tallying sees an equal number of wins (2 vs 2)
    t2_mask = (a_keys == (1, 0, 1, 0, 0)) & (b_keys == (0, 1, 0, 1, 0))
    t6_mask = (a_keys == (0, 1, 0, 0, 1)) & (b_keys == (1, 0, 0, 1, 0))
    t8_mask = (a_keys == (0, 1, 1, 0, 0)) & (b_keys == (1, 0, 0, 0, 1))
    
    tie_mask = t2_mask | t6_mask | t8_mask
    tie_data = data[tie_mask]
    
    if len(tie_data) == 0:
        return 0.0
        
    def subject_score(sub_df):
        a = sub_df['option_a_ratings'].apply(tuple)
        b = sub_df['option_b_ratings'].apply(tuple)
        
        m2 = (a == (1, 0, 1, 0, 0)) & (b == (0, 1, 0, 1, 0))
        m6 = (a == (0, 1, 0, 0, 1)) & (b == (1, 0, 0, 1, 0))
        m8 = (a == (0, 1, 1, 0, 0)) & (b == (1, 0, 0, 0, 1))
        
        score = 0.0
        count = 0
        for m in [m2, m6, m8]:
            if m.sum() > 0:
                prop_a = (sub_df.loc[m, 'response'] == 0).mean()
                score += abs(prop_a - 0.5)
                count += 1
        return score / count if count > 0 else 0.0
        
    return float(tie_data.groupby('subject_id').apply(subject_score).mean())
```

**Observed (real) value:** 0.2700 (var=0.0052)
**Other theories' values on this metric (for reference):**
- pi_2: 0.1000 (var=0.0028)
- pi_5: 0.1906 (var=0.0093)
- pi_1: 0.3550 (var=0.0125)
- pi_3: 0.1750 (var=0.0060)
- pi_4: 0.3494 (var=0.0120)
- pi_6: 0.2506 (var=0.0179)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_match = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        # Isolate trials where Tallying is perfectly tied
        if a_wins == b_wins:
            # Determine TTB prediction (first discriminating feature)
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_pred = 0
                    break
                elif b[i] > a[i]:
                    ttb_pred = 1
                    break
            else:
                continue
                
            ttb_match.append(1 if row['response'] == ttb_pred else 0)
            
    if len(ttb_match) == 0:
        return 0.5
    return float(np.mean(ttb_match))
```

**Observed (real) value:** 0.4567 (var=0.0102)
**Other theories' values on this metric (for reference):**
- pi_6: 0.6608 (var=0.0220)
- pi_2: 0.5092 (var=0.0104)
- pi_1: 0.8633 (var=0.0119)
- pi_3: 0.4992 (var=0.0151)
- pi_4: 0.8325 (var=0.0180)
- pi_5: 0.5400 (var=0.0142)

### Experiment 10
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    tie_mask = (a_wins == b_wins)
    if not np.any(tie_mask):
        return 0.5
        
    a_ties = a_ratings[tie_mask]
    b_ties = b_ratings[tie_mask]
    responses = data['response'].values[tie_mask]
    
    diff = a_ties - b_ties
    idx = np.argmax(diff != 0, axis=1)
    first_diffs = diff[np.arange(len(diff)), idx]
    ttb_choices = (first_diffs < 0).astype(int)
    
    return float(np.mean(responses == ttb_choices))
```

**Observed (real) value:** 0.4967 (var=0.0079)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5089 (var=0.0065)
- pi_6: 0.7306 (var=0.0169)
- pi_1: 0.8483 (var=0.0088)
- pi_3: 0.7044 (var=0.0153)
- pi_4: 0.8678 (var=0.0088)
- pi_5: 0.5872 (var=0.0559)


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
  "theory": "Decision-makers utilize a 'Thresholded Weighted Additive' strategy. They compute the overall weighted value of each option based on cue validities. If the difference in these weighted values exceeds a subjective threshold, the decision is driven by the weighted additive difference (WADD), allowing sensitivity to highly valid cues in extreme compensatory cases. However, if the weighted difference is below the threshold, subjects perceive the options as roughly equivalent in overall value and fall back to a simpler, less cognitively demanding Tallying heuristic, merely counting the number of winning features for each option.",
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n    \n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\"Stimulus must be of shape (2, n_features).\")\n        \n    a, b = stim[0], stim[1]\n    val = np.asarray(parameters[\"validities\"], dtype=float)\n    \n    theta = float(parameters[\"threshold\"])\n    beta_wadd = float(parameters[\"beta_wadd\"])\n    beta_tally = float(parameters[\"beta_tally\"])\n    epsilon = float(parameters[\"epsilon\"])\n    \n    # Compute WADD scores\n    wadd_a = np.dot(a, val)\n    wadd_b = np.dot(b, val)\n    wadd_diff = abs(wadd_a - wadd_b)\n    \n    # Threshold logic: if difference is salient, use WADD; else fallback to Tallying\n    if wadd_diff > theta:\n        scores = np.array([wadd_a, wadd_b])\n        beta = beta_wadd\n    else:\n        a_wins = float(np.sum(a > b))\n        b_wins = float(np.sum(b > a))\n        scores = np.array([a_wins, b_wins])\n        beta = beta_tally\n        \n    # Numerically stable softmax\n    z = beta * (scores - np.max(scores))\n    e = np.exp(z)\n    probs = e / np.sum(e)\n    \n    # Apply lapse rate\n    return (1.0 - epsilon) * probs + epsilon * np.array([0.5, 0.5])\n",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs /= probs.sum()\n    return int(np.random.choice(len(probs), p=probs))\n",
  "parameters": {
    "threshold": "[0.0, 3.0]",
    "beta_wadd": "[0.1, 20.0]",
    "beta_tally": "[0.1, 20.0]",
    "epsilon": "[0.0, 0.5]",
    "validities": "validities"
  },
  "rationale": "Following the arbiter's suggestion, this model implements a Thresholded Weighted Additive strategy. Previous models failed to simultaneously capture the strong tendency to tally in balanced scenarios and the sensitivity to validities when cue differences are extreme. By computing the WADD difference and comparing it to a threshold, the model naturally transitions between WADD (when the difference is salient) and Tallying (when options are comparable in weighted value). This explains both the guessing behavior on tied tally trials and the selective adherence to high-validity cues in extreme compensatory designs."
}
```
```

## Usage

```json
{
  "prompt_token_count": 13973,
  "candidates_token_count": 849,
  "total_token_count": 18767
}
```
