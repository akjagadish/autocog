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
- THEORY 1 = `pi_4`
- THEORY 2 = `pi_5`
- The recommendation below acts on THEORY 2 (= `pi_5`).

Propose a brand-new theory to replace the falsified idiosyncratic side bias theory. Since THEORY 1 (massive lapse rate / trial-by-trial guessing) fits the aggregate and variance data exceptionally well, the new theory should explore a different mechanism that produces near-random behavior. For instance, propose a 'Noisy Attribute' or 'Probabilistic Cue' theory where subjects attempt to use the provided feature validities (e.g., a noisy Take-The-Best or weighted additive model) but suffer from extremely high decision noise (low inverse temperature) or subjective cue validities that drift trial-to-trial. This would provide a structured, bounded-rational alternative to THEORY 1's pure lapse rate mechanism.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_4` (overall score: 0.967)

**Description**
Due to the abstract nature of the task and lack of trial-by-trial feedback, subjects do not consistently apply structured multi-attribute heuristics. Instead, their choices are dominated by high response noise or a massive lapse rate, effectively resulting in random guessing on most trials. While they may occasionally attempt to tally features or look at the most valid cue, the lack of grounding leads to a near-uniform choice probability across all stimulus pairs.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Expected a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    
    # Calculate a weak tallying signal
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Massive lapse rate dominates the choice
    p_final = (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
    
    return p_final

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- beta: [0.0, 0.5]
- epsilon: [0.8, 1.0]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.5025 (var=0.0034) vs this=0.4881 (var=0.0020)
- Experiment 2: real=0.5121 (var=0.0032) vs this=0.5106 (var=0.0028)
- Experiment 3: real=0.5117 (var=0.0085) vs this=0.4883 (var=0.0066)
- Experiment 4: real=0.4842 (var=0.0049) vs this=0.4808 (var=0.0053)
- Experiment 5: real=0.5021 (var=0.0041) vs this=0.5262 (var=0.0019)
- Experiment 6: real=0.4887 (var=0.0035) vs this=0.5097 (var=0.0037)
- Experiment 7: real=0.0479 (var=0.0010) vs this=0.0383 (var=0.0007)
- Experiment 8: real=0.0392 (var=0.0007) vs this=0.0338 (var=0.0008)


---

### `pi_3` (overall score: 0.391)

**Description**
Decision makers in multi-attribute choice tasks exhibit strategic heterogeneity. Rather than uniformly applying a single heuristic, the population consists of a mixture of strategies, predominantly Take The Best (TTB) and Tallying. On any given trial, a decision maker integrates the choice probabilities of these two heuristics according to their individual propensity (w_ttb). This mixture explains why aggregate choices in adversarial designs—where TTB and Tallying make opposing predictions—often hover around 50% alignment with either single heuristic.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    w_ttb = float(parameters["w_ttb"])
    
    # --- TTB Prediction ---
    val = np.asarray(parameters["validities"], dtype=float)
    cue_order = np.argsort(-val, kind="stable").tolist()
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        p_ttb = np.array([0.5, 0.5])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        z_ttb = beta * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
    # --- Tallying Prediction ---
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores_tal = np.array([a_wins, b_wins])
    z_tal = beta * (scores_tal - np.max(scores_tal))
    e_tal = np.exp(z_tal)
    p_tal = e_tal / np.sum(e_tal)
    
    # --- Mixture & Noise ---
    p_mix = w_ttb * p_ttb + (1.0 - w_ttb) * p_tal
    p_final = (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])
    
    return p_final

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- w_ttb: [0.0, 1.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.5025 (var=0.0034) vs this=0.5142 (var=0.0491)
- Experiment 2: real=0.5121 (var=0.0032) vs this=0.4844 (var=0.0419)
- Experiment 3: real=0.5117 (var=0.0085) vs this=0.6675 (var=0.0266)
- Experiment 4: real=0.4842 (var=0.0049) vs this=0.6754 (var=0.0184)
- Experiment 5: real=0.5021 (var=0.0041) vs this=0.7510 (var=0.0097)
- Experiment 6: real=0.4887 (var=0.0035) vs this=0.8626 (var=0.0084)
- Experiment 7: real=0.0479 (var=0.0010) vs this=0.0333 (var=0.0006)
- Experiment 8: real=0.0392 (var=0.0007) vs this=0.0292 (var=0.0007)


---

### `pi_5` (overall score: 0.354)

**Description**
Faced with abstract options and no trial-by-trial feedback, subjects abandon feature-based compensatory or non-compensatory strategies. Instead, they fall back on a strong, idiosyncratic side bias (e.g., a spatial preference for the left or right option, or a sequential preference for the first or second option). Each subject has a fixed probability of choosing Option A, which varies uniformly across the population from 0 to 1. This mechanism produces behavior that is completely independent of the feature validities or values, resulting in an aggregate alignment of ~50% with any feature-based heuristic (like Take The Best or Tallying), but driven by individual-level spatial/sequential biases rather than trial-level random guessing.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    # The subject ignores the stimulus features and relies entirely on their idiosyncratic side bias.
    p_a = float(parameters["p_a"])
    
    # Return the fixed choice probabilities for Option A and Option B
    return np.array([p_a, 1.0 - p_a])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


`parameters`:
- p_a: [0.0, 1.0]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.5025 (var=0.0034) vs this=0.5038 (var=0.0059)
- Experiment 2: real=0.5121 (var=0.0032) vs this=0.4965 (var=0.0015)
- Experiment 3: real=0.5117 (var=0.0085) vs this=0.5175 (var=0.0068)
- Experiment 4: real=0.4842 (var=0.0049) vs this=0.4958 (var=0.0046)
- Experiment 5: real=0.5021 (var=0.0041) vs this=0.4908 (var=0.0021)
- Experiment 6: real=0.4887 (var=0.0035) vs this=0.5082 (var=0.0019)
- Experiment 7: real=0.0479 (var=0.0010) vs this=0.2338 (var=0.0199)
- Experiment 8: real=0.0392 (var=0.0007) vs this=0.2696 (var=0.0189)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Extract matrices of option features
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    # Calculate the difference
    diff = a_mat - b_mat
    
    # Using exponentially decreasing weights, the sign of the weighted sum
    # is completely determined by the first non-zero difference.
    # This exactly mimics the one-reason stopping rule of Take The Best.
    weights = np.array([10000, 1000, 100, 10, 1])
    weighted_diff = np.dot(diff, weights)
    
    # If weighted_diff > 0, A is favored by the first discriminating cue (TTB predicts 0).
    # If weighted_diff < 0, B is favored by the first discriminating cue (TTB predicts 1).
    ttb_pred = (weighted_diff < 0).astype(int)
    
    # Return the proportion of choices that align with the Take The Best prediction
    return float(np.mean(ttb_pred == data['response']))
```

**Observed (real) value:** 0.5025 (var=0.0034)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8379 (var=0.0113)
- pi_2: 0.1288 (var=0.0054)
- pi_3: 0.5142 (var=0.0491)
- pi_4: 0.4881 (var=0.0020)
- pi_5: 0.5038 (var=0.0059)

### Experiment 2
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        tally_pred = 0 if a_wins > b_wins else 1
        matches.append(row['response'] == tally_pred)
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5121 (var=0.0032)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8623 (var=0.0092)
- pi_1: 0.1646 (var=0.0113)
- pi_3: 0.4844 (var=0.0419)
- pi_4: 0.5106 (var=0.0028)
- pi_5: 0.4965 (var=0.0015)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        tally_a = np.sum(a > b)
        tally_b = np.sum(b > a)
        
        # Focus only on trials where Tallying predicts a tie
        if tally_a == tally_b:
            ttb_winner = None
            # Cue order matches index order since validities are strictly decreasing
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_winner = 0
                    break
                elif b[i] > a[i]:
                    ttb_winner = 1
                    break
            
            if ttb_winner is not None:
                matches.append(row['response'] == ttb_winner)
                
    if not matches:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5117 (var=0.0085)
**Other theories' values on this metric (for reference):**
- pi_3: 0.6675 (var=0.0266)
- pi_2: 0.5067 (var=0.0049)
- pi_1: 0.8725 (var=0.0113)
- pi_4: 0.4883 (var=0.0066)
- pi_5: 0.5175 (var=0.0068)

### Experiment 4
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_aligned = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        if a_wins == b_wins:
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_choice = 0
                    break
                elif b[i] > a[i]:
                    ttb_choice = 1
                    break
            else:
                continue
                
            ttb_aligned.append(int(row['response'] == ttb_choice))
            
    if len(ttb_aligned) == 0:
        return 0.5
    return float(np.mean(ttb_aligned))
```

**Observed (real) value:** 0.4842 (var=0.0049)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5271 (var=0.0046)
- pi_3: 0.6754 (var=0.0184)
- pi_1: 0.8512 (var=0.0146)
- pi_4: 0.4808 (var=0.0053)
- pi_5: 0.4958 (var=0.0046)

### Experiment 5
**Design**
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    tally_choice = np.where(a_wins > b_wins, 0, 1)
    valid = a_wins != b_wins
    
    responses = data['response'].values
    match = (responses[valid] == tally_choice[valid])
    
    return float(np.mean(match)) if len(match) > 0 else 0.5

```

**Observed (real) value:** 0.5021 (var=0.0041)
**Other theories' values on this metric (for reference):**
- pi_4: 0.5262 (var=0.0019)
- pi_2: 0.8606 (var=0.0060)
- pi_1: 0.6196 (var=0.0018)
- pi_3: 0.7510 (var=0.0097)
- pi_5: 0.4908 (var=0.0021)

### Experiment 6
**Design**
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    responses = data['response'].values
    
    valid_mask = a_wins != b_wins
    if not np.any(valid_mask):
        return 0.5
        
    tally_winner = (b_wins > a_wins).astype(int)
    matches = (responses[valid_mask] == tally_winner[valid_mask])
    
    return float(np.mean(matches))
```

**Observed (real) value:** 0.4887 (var=0.0035)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8918 (var=0.0073)
- pi_4: 0.5097 (var=0.0037)
- pi_1: 0.8738 (var=0.0083)
- pi_3: 0.8626 (var=0.0084)
- pi_5: 0.5082 (var=0.0019)

### Experiment 7
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Calculate the proportion of 'B' choices (response == 1) for each subject
    # Then compute the absolute deviation from 0.5 (random guessing)
    # Average this deviation across all subjects in the data
    return float(data.groupby('subject_id')['response'].mean().apply(lambda x: abs(x - 0.5)).mean())
```

**Observed (real) value:** 0.0479 (var=0.0010)
**Other theories' values on this metric (for reference):**
- pi_4: 0.0383 (var=0.0007)
- pi_5: 0.2338 (var=0.0199)
- pi_1: 0.0331 (var=0.0007)
- pi_2: 0.0210 (var=0.0005)
- pi_3: 0.0333 (var=0.0006)

### Experiment 8
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    subject_means = data.groupby('subject_id')['response'].mean()
    return float(np.abs(subject_means - 0.5).mean())
```

**Observed (real) value:** 0.0392 (var=0.0007)
**Other theories' values on this metric (for reference):**
- pi_5: 0.2696 (var=0.0189)
- pi_4: 0.0338 (var=0.0008)
- pi_1: 0.0296 (var=0.0006)
- pi_2: 0.0210 (var=0.0004)
- pi_3: 0.0292 (var=0.0007)


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
  "theory": "Subjects attempt to integrate all available information by computing the subjective value of each option based on the provided feature validities (Weighted Additive strategy). However, due to the abstract nature of the task and the absence of trial-by-trial feedback, they suffer from extremely high decision noise. This translates to a very low inverse temperature in their choice rule, producing behavior that appears near-random but is actually generated by a structured, bounded-rational compensatory process.",
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n    \n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\"Expected a (2, n_features) stimulus.\")\n    \n    a, b = stim[0], stim[1]\n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    \n    # Calculate weighted additive values for each option\n    val_a = np.sum(validities * a)\n    val_b = np.sum(validities * b)\n    scores = np.array([val_a, val_b])\n    \n    # Apply softmax with extremely high decision noise (low beta)\n    beta = float(parameters[\"beta\"])\n    z = beta * (scores - np.max(scores))\n    e = np.exp(z)\n    p = e / np.sum(e)\n    \n    return p\n",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs /= probs.sum()\n    return int(np.random.choice(len(probs), p=probs))\n",
  "parameters": {
    "beta": "[0.0, 0.15]",
    "validities": "validities"
  },
  "rationale": "Following the arbiter's suggestion, this theory replaces the idiosyncratic side bias with a 'Noisy Attribute' mechanism. Subjects use a Weighted Additive (WADD) model, attempting to factor in the provided cue validities. However, the lack of grounding leads to extremely high decision noise (represented by a very low inverse temperature, beta). This structured, bounded-rational approach naturally produces the near-random choice patterns observed across the experiments, successfully matching the aggregate and variance metrics while offering a more plausible cognitive mechanism than a pure uniform lapse rate."
}
```
```

## Usage

```json
{
  "prompt_token_count": 10383,
  "candidates_token_count": 574,
  "total_token_count": 12729
}
```
