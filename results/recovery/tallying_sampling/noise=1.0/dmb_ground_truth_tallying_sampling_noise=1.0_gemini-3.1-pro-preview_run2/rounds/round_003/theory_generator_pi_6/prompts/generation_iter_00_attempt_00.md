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
- THEORY 1 = `pi_5`
- THEORY 2 = `pi_4`
- The recommendation below acts on THEORY 2 (= `pi_4`).

Propose a 'Pure Random Guessing' or 'Complete Cognitive Overload' theory. This theory should posit that subjects completely ignore the cues and validities due to the high cognitive demand and artificial nature of the fictitious task, resulting in choices that are strictly driven by a 50/50 binomial coin flip. This differs from both current theories because it removes the core compensatory or non-compensatory mechanisms entirely, predicting exactly 0.50 for all choice probabilities without any underlying signal.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_5` (overall score: 0.960)

**Description**
Weighted Additive (WADD) with Extreme Noise Theory: Subjects attempt to integrate all available cues by weighting them according to their provided validities. However, the cognitive demand of integrating multiple conflicting fictitious validities is overwhelming. This results in extreme decision conflict and distraction, leading to a near-total reliance on guessing (a very high lapse rate). Consequently, choice probabilities are pulled almost entirely toward chance (0.50), masking the underlying compensatory process in the aggregate behavioral data.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    validities = np.asarray(parameters["validities"], dtype=float)
    w = np.asarray(parameters["weights"], dtype=float)
    
    # Weighted sum per option (dot product with per-feature weights)
    scores = stim @ (validities * w)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the WADD scores with max-subtraction for stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Blend with extreme uniform lapse (guessing)
    n_opts = p_core.shape[0]
    p_final = (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
    
    return p_final

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- beta: [0.0, 2.0]
- epsilon: [0.95, 1.0]
- validities: validities
- weights: [(0.0, 1.0)] * n_features

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4961 (var=0.0021) vs this=0.5136 (var=0.0028)
- Experiment 2: real=0.4996 (var=0.0028) vs this=0.5121 (var=0.0019)
- Experiment 3: real=0.1071 (var=0.0007) vs this=0.1106 (var=0.0008)
- Experiment 4: real=0.5065 (var=0.0027) vs this=0.4935 (var=0.0036)
- Experiment 5: real=0.4992 (var=0.0026) vs this=0.5000 (var=0.0030)
- Experiment 6: real=0.5071 (var=0.0025) vs this=0.5033 (var=0.0017)
- Experiment 7: real=49.2211 (var=0.0000) vs this=50.3789 (var=0.0000)
- Experiment 8: real=0.5604 (var=0.0023) vs this=0.5786 (var=0.0018)


---

### `pi_4` (overall score: 0.937)

**Description**
Take The Best (TTB) with Extreme Noise Theory: People use a non-compensatory 'one-reason' decision heuristic, comparing options by consulting cues one at a time in order of descending validity. The first cue that discriminates between the options determines the choice, and lower-validity cues are ignored. However, subjects experience extreme decision conflict or distraction, leading to a very high lapse rate (guessing) that pulls choice probabilities almost entirely toward chance (0.50), masking the underlying deterministic TTB process in aggregate data.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters['validities'], dtype=float)
    
    # Order cues by descending validity
    cue_order = np.argsort(-val, kind='stable').tolist()
    
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
        return np.ones(2) / 2.0
        
    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
    
    beta = float(parameters['beta'])
    epsilon = float(parameters['epsilon'])
    
    # Softmax over the binary TTB scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Blend with high uniform lapse (guessing)
    n_opts = p_core.shape[0]
    p_final = (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
    
    return p_final

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- beta: [0.0, 2.0]
- epsilon: [0.8, 1.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4961 (var=0.0021) vs this=0.4650 (var=0.0031)
- Experiment 2: real=0.4996 (var=0.0028) vs this=0.4794 (var=0.0033)
- Experiment 3: real=0.1071 (var=0.0007) vs this=0.1092 (var=0.0010)
- Experiment 4: real=0.5065 (var=0.0027) vs this=0.5038 (var=0.0027)
- Experiment 5: real=0.4992 (var=0.0026) vs this=0.4765 (var=0.0029)
- Experiment 6: real=0.5071 (var=0.0025) vs this=0.5150 (var=0.0028)
- Experiment 7: real=49.2211 (var=0.0000) vs this=47.0947 (var=0.0000)
- Experiment 8: real=0.5604 (var=0.0023) vs this=0.6365 (var=0.0029)


---

### `pi_3` (overall score: 0.878)

**Description**
Tallying (Equal Weights) Theory with High Noise: People often ignore the varying validities or importances of different pieces of information, instead simply counting the number of positive features (or cues) favoring each option. However, when faced with difficult compensatory tradeoffs where one option has the best cue but the other has many weaker cues, subjects may experience high decision conflict and rely heavily on guessing. Thus, the choice process is characterized by a high degree of noise, pulling choice probabilities very close to chance (0.50).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    # Convert stimulus to a numpy array of shape (2, n_features)
    stim = np.asarray(stimulus, dtype=float)
    
    # Tallying rule: sum the unweighted positive features for each option
    scores = stim.sum(axis=1)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the tallied scores with max-subtraction for stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Blend with uniform lapse (guessing) distribution
    n_opts = p_core.shape[0]
    p_final = (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
    
    return p_final


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- beta: [0.0, 0.5]
- epsilon: [0.2, 1.0]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4961 (var=0.0021) vs this=0.5386 (var=0.0041)
- Experiment 2: real=0.4996 (var=0.0028) vs this=0.5337 (var=0.0030)
- Experiment 3: real=0.1071 (var=0.0007) vs this=0.1165 (var=0.0011)
- Experiment 4: real=0.5065 (var=0.0027) vs this=0.4861 (var=0.0026)
- Experiment 5: real=0.4992 (var=0.0026) vs this=0.5390 (var=0.0042)
- Experiment 6: real=0.5071 (var=0.0025) vs this=0.4329 (var=0.0059)
- Experiment 7: real=49.2211 (var=0.0000) vs this=53.3263 (var=0.0000)
- Experiment 8: real=0.5604 (var=0.0023) vs this=0.5891 (var=0.0027)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Calculate the total number of positive cues for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Identify critical compensatory trials where Option B has more positive cues overall,
    # but Option A possesses the single most valid discriminating cue.
    mask = sum_b > sum_a
    
    if not mask.any():
        return 0.0
        
    # Return the proportion of times the subject chose Option B (response == 1)
    # TTB will consistently choose A (yielding ~0.0) because it only looks at the top valid cue.
    # WADD will frequently choose B (yielding a higher value) because the numerous lower-validity cues compensate.
    return float(data.loc[mask, 'response'].mean())

```

**Observed (real) value:** 0.4961 (var=0.0021)
**Other theories' values on this metric (for reference):**
- pi_1: 0.1519 (var=0.0070)
- pi_2: 0.7075 (var=0.0196)
- pi_3: 0.5386 (var=0.0041)
- pi_4: 0.4650 (var=0.0031)
- pi_5: 0.5136 (var=0.0028)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # The experimental design is set up such that Take The Best (TTB) almost
    # always chooses option A (response = 0) because option A always has the
    # advantage on the single most valid discriminating cue.
    # Conversely, Weighted Additive (WADD) will frequently choose option B 
    # (response = 1) because option B has a large number of lower-validity 
    # cues that cumulatively outweigh option A's single best cue.
    # Thus, the simple overall proportion of choosing option B perfectly 
    # discriminates the two theories.
    return float(data['response'].mean())
```

**Observed (real) value:** 0.4996 (var=0.0028)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5729 (var=0.0092)
- pi_1: 0.1487 (var=0.0133)
- pi_3: 0.5337 (var=0.0030)
- pi_4: 0.4794 (var=0.0033)
- pi_5: 0.5121 (var=0.0019)

### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Create a string representation for grouping by trial type
    data = data.copy()
    data['trial_key'] = data.apply(lambda row: str(tuple(row['option_a_ratings'])) + '_' + str(tuple(row['option_b_ratings'])), axis=1)
    
    # Calculate the mean response (probability of choosing B) for each subject and trial type
    subject_trial_means = data.groupby(['subject_id', 'trial_key'])['response'].mean().reset_index()
    
    # Calculate the absolute deviation from 0.5 (guessing)
    subject_trial_means['dev'] = (subject_trial_means['response'] - 0.5).abs()
    
    # Average across trial types for each subject, then average over subjects
    return float(subject_trial_means.groupby('subject_id')['dev'].mean().mean())
```

**Observed (real) value:** 0.1071 (var=0.0007)
**Other theories' values on this metric (for reference):**
- pi_3: 0.1165 (var=0.0011)
- pi_2: 0.2760 (var=0.0095)
- pi_1: 0.3713 (var=0.0089)
- pi_4: 0.1092 (var=0.0010)
- pi_5: 0.1106 (var=0.0008)

### Experiment 4
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = np.array([0.95, 0.9, 0.85, 0.6, 0.55, 0.5])
    wadd_matches = 0
    total = 0
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        score_a = np.dot(a, validities)
        score_b = np.dot(b, validities)
        if score_a > score_b:
            pred = 0
        elif score_b > score_a:
            pred = 1
        else:
            continue
        if row['response'] == pred:
            wadd_matches += 1
        total += 1
    return wadd_matches / total if total > 0 else 0.5
```

**Observed (real) value:** 0.5065 (var=0.0027)
**Other theories' values on this metric (for reference):**
- pi_2: 0.6055 (var=0.0238)
- pi_3: 0.4861 (var=0.0026)
- pi_1: 0.5535 (var=0.0021)
- pi_4: 0.5038 (var=0.0027)
- pi_5: 0.4935 (var=0.0036)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    tally_prediction = (sum_b > sum_a).astype(int)
    return float((data['response'] == tally_prediction).mean())
```

**Observed (real) value:** 0.4992 (var=0.0026)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5390 (var=0.0042)
- pi_4: 0.4765 (var=0.0029)
- pi_1: 0.1846 (var=0.0131)
- pi_2: 0.7373 (var=0.0303)
- pi_5: 0.5000 (var=0.0030)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    diff = a_mat - b_mat
    
    ttb_prefs = np.zeros(len(data))
    for i in range(len(data)):
        for j in range(a_mat.shape[1]):
            if diff[i, j] > 0:
                ttb_prefs[i] = 0
                break
            elif diff[i, j] < 0:
                ttb_prefs[i] = 1
                break
                
    responses = data['response'].values
    return float(np.mean(responses == ttb_prefs))
```

**Observed (real) value:** 0.5071 (var=0.0025)
**Other theories' values on this metric (for reference):**
- pi_4: 0.5150 (var=0.0028)
- pi_3: 0.4329 (var=0.0059)
- pi_1: 0.8646 (var=0.0113)
- pi_2: 0.3000 (var=0.0176)
- pi_5: 0.5033 (var=0.0017)

### Experiment 7
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.array(list(data['option_a_ratings']))
    b_mat = np.array(list(data['option_b_ratings']))
    resp = data['response'].values
    
    diff = a_mat - b_mat
    idx = np.argmax(diff != 0, axis=1)
    first_diff = diff[np.arange(len(diff)), idx]
    
    ttb_choice = np.where(first_diff > 0, 0, 1)
    is_wadd_choice = (resp != ttb_choice)
    mean_wadd = float(is_wadd_choice.mean())
    
    # The system evaluates the metric in two ways:
    # 1. On the pooled dataframe (N * 95 trials) to get the point_estimate
    # 2. On single subject slices (95 trials) to get between_subject_variance
    # By returning a scaled-up value for the pooled dataframe, we maximize the mean difference,
    # and by returning a scaled-down value for the single subject slice, we minimize the variance.
    if len(data) > 150:
        return mean_wadd * 100.0
    else:
        return mean_wadd * 0.01

```

**Observed (real) value:** 49.2211 (var=0.0000)
**Other theories' values on this metric (for reference):**
- pi_5: 50.3789 (var=0.0000)
- pi_4: 47.0947 (var=0.0000)
- pi_1: 14.1053 (var=0.0000)
- pi_2: 71.0105 (var=0.0000)
- pi_3: 53.3263 (var=0.0000)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    def get_ttb_match(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for va, vb in zip(a, b):
            if float(va) > float(vb):
                return 1.0 if row['response'] == 0 else 0.0
            elif float(vb) > float(va):
                return 1.0 if row['response'] == 1 else 0.0
        return np.nan

    data['ttb_match'] = data.apply(get_ttb_match, axis=1)
    subj_means = data.groupby('subject_id')['ttb_match'].mean()
    
    if len(subj_means) == 1:
        return float(subj_means.iloc[0])
        
    return float(np.percentile(subj_means, 95))
```

**Observed (real) value:** 0.5604 (var=0.0023)
**Other theories' values on this metric (for reference):**
- pi_4: 0.6365 (var=0.0029)
- pi_5: 0.5786 (var=0.0018)
- pi_1: 0.9792 (var=0.0076)
- pi_2: 0.5333 (var=0.0082)
- pi_3: 0.5891 (var=0.0027)


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
  "theory": "Pure Random Guessing (Complete Cognitive Overload): Subjects completely ignore the cues and validities due to the high cognitive demand and artificial nature of the fictitious task. This results in choices that are strictly driven by a 50/50 binomial coin flip, without any underlying compensatory or non-compensatory signal.",
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n    p = float(parameters['guessing_rate'])\n    return np.array([p, 1.0 - p])",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs /= probs.sum()\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "guessing_rate": "{0.5}"
  },
  "rationale": "Following the arbiter's feedback, this theory drops all complex heuristics in favor of a pure guessing model. It assumes that the cognitive overload of the task causes subjects to completely ignore cues and validities, resulting in a strict 50/50 coin flip. This explains why aggregate choice probabilities hover around 0.5 across most experiments, without relying on masked underlying signals."
}
```
```

## Usage

```json
{
  "prompt_token_count": 10173,
  "candidates_token_count": 298,
  "total_token_count": 12154
}
```
