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
- THEORY 2 = `pi_5`
- The recommendation below acts on THEORY 2 (= `pi_5`).

Propose a 'Probabilistic Leaky Competing Accumulator' theory. Instead of a strict deterministic sequential search (like Theory 2) or a highly parameterized recurrent network (like Theory 1), this theory should posit that decision-makers probabilistically sample cues proportional to their validities. Evidence from sampled cues accumulates in competing accumulators (one for each option) subject to leakage and lateral inhibition. This allows the model to exhibit fast, non-compensatory choices when high-validity cues are sampled early and push the accumulator past a threshold, while also naturally producing compensatory, tally-like behavior when evidence accumulation is prolonged due to leakage or high thresholds. This stochastic sampling approach can better capture the variance and intermediate metrics observed across all experiments.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_6` (overall score: 0.672)

**Description**
Parallel Constraint Satisfaction (PCS) Decision Network with Softmax Cue Weighting. Choices emerge from a recurrent neural network where options and features bidirectionally interact. Options accumulate evidence from features and mutually inhibit each other. Options also send feedback to features, amplifying features that support the leading option (coherence shift). To allow the model to flexibly transition between compensatory and non-compensatory (lexicographic) behavior without destabilizing the network, the initial cue validities are transformed via a softmax function controlled by a temperature parameter (tau). This ensures the highest-validity cue can decisively dominate the parallel accumulation when necessary, while bounded inhibition and feedback terms prevent runaway dynamics.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    tau = float(parameters["tau"])
    lam = float(parameters["lam"])
    gamma = float(parameters["gamma"])
    kappa = float(parameters["kappa"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax transformation of validities to allow lexicographic dominance
    z_v = tau * validities
    z_v = z_v - np.max(z_v)
    weights = np.exp(z_v) / np.sum(np.exp(z_v))
    
    # Initialize activations: Options at 0, Cues at their resting weights
    O = np.array([0.0, 0.0])
    C = weights.copy()
    
    w_A = a - b
    w_B = b - a
    
    alpha = 0.1
    n_iter = 50
    
    for _ in range(n_iter):
        # Net input to options: evidence from cues minus lateral inhibition
        net_O_A = np.sum(w_A * C) - lam * O[1]
        net_O_B = np.sum(w_B * C) - lam * O[0]
        
        # Net input to cues: feedback from options
        net_C = gamma * w_A * O[0] + gamma * w_B * O[1]
        
        # Update options (McClelland & Rumelhart rule)
        net_O = np.array([net_O_A, net_O_B])
        delta_O = np.where(net_O > 0,
                           alpha * net_O * (1.0 - O) - kappa * O,
                           alpha * net_O * O - kappa * O)
        O = np.clip(O + delta_O, 0.0, 1.0)
        
        # Update cues (decay towards resting weights)
        delta_C = np.where(net_C > 0,
                           alpha * net_C * (1.0 - C) - kappa * (C - weights),
                           alpha * net_C * C - kappa * (C - weights))
        C = np.clip(C + delta_C, 0.0, 1.0)
        
    scores = O
    
    # Softmax choice rule
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


`parameters`:
- tau: [0.0, 10.0]
- lam: [0.0, 2.0]
- gamma: [0.0, 2.0]
- kappa: [0.0, 1.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4113 (var=0.0093) vs this=0.3375 (var=0.0246)
- Experiment 2: real=0.5900 (var=0.0027) vs this=0.6069 (var=0.0138)
- Experiment 3: real=0.6004 (var=0.0022) vs this=0.4473 (var=0.0141)
- Experiment 4: real=0.4131 (var=0.0041) vs this=0.5228 (var=0.0230)
- Experiment 5: real=-0.0400 (var=0.0356) vs this=0.1133 (var=0.0422)
- Experiment 6: real=0.4238 (var=0.0036) vs this=0.4866 (var=0.0089)
- Experiment 7: real=-0.0175 (var=0.0255) vs this=-0.3225 (var=0.1029)
- Experiment 8: real=0.8050 (var=0.0264) vs this=1.1000 (var=0.1319)
- Experiment 9: real=0.4158 (var=0.0019) vs this=0.4465 (var=0.0207)
- Experiment 10: real=0.4463 (var=0.0140) vs this=0.4232 (var=0.0422)


---

### `pi_5` (overall score: 0.620)

**Description**
Sequential Evidence Accumulation. Decision-makers inspect features sequentially in decreasing order of validity. At each step, the validity-weighted difference between the options' features is added to an accumulated evidence tally. If the absolute value of this accumulated evidence exceeds a critical threshold, search stops immediately and a decision is made based on the current tally (mimicking Take-The-Best when the threshold is low). If all features are exhausted without crossing the threshold, a choice is made probabilistically based on the final accumulated tally (mimicking compensatory strategies like Weighted Additive when the threshold is high).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    threshold = float(parameters["threshold"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Sort features by validity in descending order (stable sort for ties)
    order = np.argsort(-validities, kind='stable')
    
    a, b = stim[0], stim[1]
    evidence = 0.0
    
    # Sequential search and evidence accumulation
    for idx in order:
        diff = a[idx] - b[idx]
        evidence += validities[idx] * diff
        
        # Stop search if accumulated evidence exceeds the threshold
        if abs(evidence) >= threshold:
            break
            
    # Convert the final evidence into choice probabilities.
    # Evidence represents the accumulated advantage of Option A over Option B.
    scores = np.array([evidence, 0.0])
    
    # Softmax over the scores
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Uniform lapse blended into the softmax
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


`parameters`:
- threshold: [0.01, 1.5]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4113 (var=0.0093) vs this=0.1256 (var=0.0087)
- Experiment 2: real=0.5900 (var=0.0027) vs this=0.7700 (var=0.0166)
- Experiment 3: real=0.6004 (var=0.0022) vs this=0.5810 (var=0.0826)
- Experiment 4: real=0.4131 (var=0.0041) vs this=0.4400 (var=0.1377)
- Experiment 5: real=-0.0400 (var=0.0356) vs this=0.0033 (var=0.0219)
- Experiment 6: real=0.4238 (var=0.0036) vs this=0.3606 (var=0.0862)
- Experiment 7: real=-0.0175 (var=0.0255) vs this=-0.1987 (var=0.1125)
- Experiment 8: real=0.8050 (var=0.0264) vs this=0.9350 (var=0.5647)
- Experiment 9: real=0.4158 (var=0.0019) vs this=0.2800 (var=0.0471)
- Experiment 10: real=0.4463 (var=0.0140) vs this=0.1789 (var=0.0139)


---

### `pi_4` (overall score: 0.595)

**Description**
Probabilistic Strategy Selection (Mixture of TTB and Tallying)

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    p_lex = float(parameters["p_lex"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    a, b = stim[0], stim[1]
    
    # Strategy 1: Take-The-Best (Lexicographic)
    order = np.argsort(-validities, kind='stable')
    scores_ttb = np.zeros(2)
    for idx in order:
        if a[idx] > b[idx]:
            scores_ttb[0] = 1.0
            break
        elif b[idx] > a[idx]:
            scores_ttb[1] = 1.0
            break
            
    # Strategy 2: Tallying (Compensatory)
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores_tal = np.array([a_wins, b_wins])
    
    # Softmax for TTB
    z_ttb = beta * (scores_ttb - scores_ttb.max())
    e_ttb = np.exp(z_ttb)
    p_ttb = e_ttb / e_ttb.sum()
    
    # Softmax for Tallying
    z_tal = beta * (scores_tal - scores_tal.max())
    e_tal = np.exp(z_tal)
    p_tal = e_tal / e_tal.sum()
    
    # Mixture of strategies
    p_core = p_lex * p_ttb + (1.0 - p_lex) * p_tal
    
    # Uniform lapse blended into the mixture
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


`parameters`:
- p_lex: [0.0, 1.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.4113 (var=0.0093) vs this=0.5594 (var=0.0459)
- Experiment 2: real=0.5900 (var=0.0027) vs this=0.6138 (var=0.0353)
- Experiment 3: real=0.6004 (var=0.0022) vs this=0.5702 (var=0.0387)
- Experiment 4: real=0.4131 (var=0.0041) vs this=0.5209 (var=0.0509)
- Experiment 5: real=-0.0400 (var=0.0356) vs this=-0.0083 (var=0.0373)
- Experiment 6: real=0.4238 (var=0.0036) vs this=0.3266 (var=0.0202)
- Experiment 7: real=-0.0175 (var=0.0255) vs this=0.4213 (var=0.0895)
- Experiment 8: real=0.8050 (var=0.0264) vs this=0.3325 (var=0.0412)
- Experiment 9: real=0.4158 (var=0.0019) vs this=0.4679 (var=0.0428)
- Experiment 10: real=0.4463 (var=0.0140) vs this=0.4874 (var=0.0495)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    tallying_consistent = 0
    total_dissociation_trials = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        sum_a = np.sum(a)
        sum_b = np.sum(b)
        
        # Identify dissociation trials: one option has more features, but lacks the first (highest validity) feature
        if sum_a > sum_b and a[0] == 0:
            total_dissociation_trials += 1
            if row['response'] == 0:
                tallying_consistent += 1
        elif sum_b > sum_a and b[0] == 0:
            total_dissociation_trials += 1
            if row['response'] == 1:
                tallying_consistent += 1
                
    if total_dissociation_trials == 0:
        return 0.5
        
    return float(tallying_consistent / total_dissociation_trials)
```

**Observed (real) value:** 0.4113 (var=0.0093)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8669 (var=0.0105)
- pi_2: 0.4050 (var=0.0960)
- pi_3: 0.1544 (var=0.0114)
- pi_4: 0.5594 (var=0.0459)
- pi_5: 0.1256 (var=0.0087)
- pi_6: 0.3375 (var=0.0246)

### Experiment 2
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_f1 = np.array([a[0] for a in data['option_a_ratings']])
    b_f1 = np.array([b[0] for b in data['option_b_ratings']])
    resp = data['response'].values
    chosen_f1 = np.where(resp == 0, a_f1, b_f1)
    return float(np.mean(chosen_f1))
```

**Observed (real) value:** 0.5900 (var=0.0027)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5321 (var=0.0463)
- pi_1: 0.2685 (var=0.0055)
- pi_3: 0.8462 (var=0.0136)
- pi_4: 0.6138 (var=0.0353)
- pi_5: 0.7700 (var=0.0166)
- pi_6: 0.6069 (var=0.0138)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def ttb_match(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]:
                return row['response'] == 0
            elif b[i] > a[i]:
                return row['response'] == 1
        return False

    return float(data.apply(ttb_match, axis=1).mean())
```

**Observed (real) value:** 0.6004 (var=0.0022)
**Other theories' values on this metric (for reference):**
- pi_3: 0.8496 (var=0.0075)
- pi_2: 0.3115 (var=0.0131)
- pi_1: 0.2550 (var=0.0045)
- pi_4: 0.5702 (var=0.0387)
- pi_5: 0.5810 (var=0.0826)
- pi_6: 0.4473 (var=0.0141)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Calculate the total number of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Select trials where Option B has more positive features than Option A
    # In the experimental design (Trials 1, 2, 3, 5), Option A is endorsed by the 
    # single highest-validity discriminating cue, but Option B has a higher sheer 
    # number of lower-validity cues.
    mask = sum_b > sum_a
    
    if not mask.any():
        return 0.5
        
    # Return the proportion of times Option B was chosen (response == 1)
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.4131 (var=0.0041)
**Other theories' values on this metric (for reference):**
- pi_2: 0.7538 (var=0.0204)
- pi_3: 0.1300 (var=0.0100)
- pi_1: 0.8506 (var=0.0097)
- pi_4: 0.5209 (var=0.0509)
- pi_5: 0.4400 (var=0.1377)
- pi_6: 0.5228 (var=0.0230)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    data = data.copy()
    data['a_tup'] = data['option_a_ratings'].apply(tuple)
    data['b_tup'] = data['option_b_ratings'].apply(tuple)
    
    # Trial 1: A=[1, 0, 0, 0, 0], B=[0, 1, 1, 0, 0]
    m1_norm = (data['a_tup'] == (1, 0, 0, 0, 0)) & (data['b_tup'] == (0, 1, 1, 0, 0))
    m1_swap = (data['a_tup'] == (0, 1, 1, 0, 0)) & (data['b_tup'] == (1, 0, 0, 0, 0))
    p_a_t1_norm = (data.loc[m1_norm, 'response'] == 0).mean() if m1_norm.sum() > 0 else np.nan
    p_a_t1_swap = (data.loc[m1_swap, 'response'] == 1).mean() if m1_swap.sum() > 0 else np.nan
    t1_vals = [x for x in [p_a_t1_norm, p_a_t1_swap] if not np.isnan(x)]
    p_a_t1 = np.mean(t1_vals) if t1_vals else 0.5
    
    # Trial 3: A=[1, 0, 0, 0, 0], B=[0, 1, 1, 1, 1]
    m3_norm = (data['a_tup'] == (1, 0, 0, 0, 0)) & (data['b_tup'] == (0, 1, 1, 1, 1))
    m3_swap = (data['a_tup'] == (0, 1, 1, 1, 1)) & (data['b_tup'] == (1, 0, 0, 0, 0))
    p_a_t3_norm = (data.loc[m3_norm, 'response'] == 0).mean() if m3_norm.sum() > 0 else np.nan
    p_a_t3_swap = (data.loc[m3_swap, 'response'] == 1).mean() if m3_swap.sum() > 0 else np.nan
    t3_vals = [x for x in [p_a_t3_norm, p_a_t3_swap] if not np.isnan(x)]
    p_a_t3 = np.mean(t3_vals) if t3_vals else 0.5
    
    return float(p_a_t1 - p_a_t3)
```

**Observed (real) value:** -0.0400 (var=0.0356)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0083 (var=0.0373)
- pi_2: 0.2283 (var=0.0913)
- pi_1: 0.0117 (var=0.0164)
- pi_3: -0.0150 (var=0.0194)
- pi_5: 0.0033 (var=0.0219)
- pi_6: 0.1133 (var=0.0422)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = np.array([0.95, 0.85, 0.8, 0.75, 0.6, 0.5])
    a_mat = np.vstack(data['option_a_ratings'].values)
    b_mat = np.vstack(data['option_b_ratings'].values)
    
    a_scores = a_mat @ validities
    b_scores = b_mat @ validities
    
    # Identify critical trials where the sum of validities is higher for Option B
    critical_trials = b_scores > a_scores
    
    if not np.any(critical_trials):
        return 0.5
        
    # Return the proportion of times Option B was chosen in these critical trials
    return float(data.loc[critical_trials, 'response'].mean())
```

**Observed (real) value:** 0.4238 (var=0.0036)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5663 (var=0.0390)
- pi_4: 0.3266 (var=0.0202)
- pi_1: 0.5091 (var=0.0050)
- pi_3: 0.1187 (var=0.0070)
- pi_5: 0.3606 (var=0.0862)
- pi_6: 0.4866 (var=0.0089)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0, 0]  B=[0, 1, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Convert option A ratings to tuples for easy matching
    a_tuples = data['option_a_ratings'].apply(tuple)
    
    # Trial 1: TTB chooses A, Tallying chooses A. 
    # Accumulator chooses A (low threshold) or B (high threshold).
    t1_mask = a_tuples == (1, 0, 0, 0, 1, 1, 1)
    
    # Trial 3: TTB chooses A, Tallying chooses B.
    # Accumulator ALWAYS chooses A (evidence is strictly positive at every step).
    t3_mask = a_tuples == (1, 0, 1, 1, 0, 0, 0)
    
    # Calculate probability of choosing Option A (response == 0)
    p_a_t1 = (data.loc[t1_mask, 'response'] == 0).mean()
    p_a_t3 = (data.loc[t3_mask, 'response'] == 0).mean()
    
    if pd.isna(p_a_t1): p_a_t1 = 0.5
    if pd.isna(p_a_t3): p_a_t3 = 0.5
    
    # Metric: Difference in probability of choosing A between Trial 1 and Trial 3
    return float(p_a_t1 - p_a_t3)
```

**Observed (real) value:** -0.0175 (var=0.0255)
**Other theories' values on this metric (for reference):**
- pi_4: 0.4213 (var=0.0895)
- pi_5: -0.1987 (var=0.1125)
- pi_1: 0.6650 (var=0.0736)
- pi_2: -0.0462 (var=0.2972)
- pi_3: -0.0563 (var=0.0091)
- pi_6: -0.3225 (var=0.1029)

### Experiment 8
**Design**
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    a_tuples = data['option_a_ratings'].apply(tuple)
    
    t1_a = (0, 1, 1, 1, 0, 0, 0)
    t2_a = (1, 0, 0, 0, 1, 1, 1)
    
    is_t1 = a_tuples == t1_a
    is_t2 = a_tuples == t2_a
    
    t1_score = (data.loc[is_t1, 'response'] == 0).mean() if is_t1.any() else 0.0
    t2_score = (data.loc[is_t2, 'response'] == 1).mean() if is_t2.any() else 0.0
    
    return float(t1_score + t2_score)

```

**Observed (real) value:** 0.8050 (var=0.0264)
**Other theories' values on this metric (for reference):**
- pi_5: 0.9350 (var=0.5647)
- pi_4: 0.3325 (var=0.0412)
- pi_1: 0.2812 (var=0.0521)
- pi_2: 1.0337 (var=0.3925)
- pi_3: 0.3200 (var=0.0568)
- pi_6: 1.1000 (var=0.1319)

### Experiment 9
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Calculate the total number of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Tallying prediction: choose the option with more positive features
    # Returns 0 if A has more, 1 if B has more
    tally_prediction = (sum_b > sum_a).astype(int)
    
    # Calculate the proportion of trials where the subject's response matches the Tallying prediction
    return float((data['response'] == tally_prediction).mean())
```

**Observed (real) value:** 0.4158 (var=0.0019)
**Other theories' values on this metric (for reference):**
- pi_6: 0.4465 (var=0.0207)
- pi_5: 0.2800 (var=0.0471)
- pi_1: 0.8590 (var=0.0108)
- pi_2: 0.5173 (var=0.0372)
- pi_3: 0.1713 (var=0.0111)
- pi_4: 0.4679 (var=0.0428)

### Experiment 10
**Design**
  A=[0, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Mask for Trial 3: A=[0, 0, 1, 1, 1, 1, 1, 1, 1], B=[1, 1, 0, 0, 0, 0, 0, 0, 0]
    t3_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1, 1, 1, 1, 1)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0, 0, 0, 0, 0))
    
    if t3_mask.sum() == 0:
        return 0.0
        
    # Return the probability of choosing Option A in Trial 3
    p_a_t3 = 1.0 - data[t3_mask]['response'].mean()
    return float(p_a_t3)
```

**Observed (real) value:** 0.4463 (var=0.0140)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1789 (var=0.0139)
- pi_6: 0.4232 (var=0.0422)
- pi_1: 0.8758 (var=0.0146)
- pi_2: 0.8168 (var=0.0263)
- pi_3: 0.1411 (var=0.0149)
- pi_4: 0.4874 (var=0.0495)


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
  "theory": "Probabilistic Leaky Competing Accumulator (LCA). Decision-makers probabilistically sample cues proportional to their validities. Evidence from sampled cues accumulates in competing accumulators (one for each option) subject to leakage and lateral inhibition. This allows the model to exhibit fast, non-compensatory choices when high-validity cues are sampled early and push the accumulator past a threshold, while also naturally producing compensatory, tally-like behavior when evidence accumulation is prolonged due to leakage or high thresholds. This stochastic sampling approach captures the variance and intermediate metrics observed across experiments.",
  "predict": "def predict(parameters, stimulus, history):\n    import numpy as np\n    \n    stim = np.asarray(stimulus, dtype=float)\n    a, b = stim[0], stim[1]\n    \n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    threshold = float(parameters[\"threshold\"])\n    leak = float(parameters[\"leak\"])\n    inhibition = float(parameters[\"inhibition\"])\n    beta = float(parameters[\"beta\"])\n    epsilon = float(parameters[\"epsilon\"])\n    max_steps = int(parameters[\"max_steps\"])\n    \n    # Probabilities for sampling cues\n    cue_probs = validities / np.sum(validities)\n    \n    n_sims = 50\n    p_total = np.zeros(2)\n    \n    for _ in range(n_sims):\n        A_acc = 0.0\n        B_acc = 0.0\n        \n        for _ in range(max_steps):\n            # Sample a cue proportional to its validity\n            idx = np.random.choice(len(validities), p=cue_probs)\n            \n            I_A = a[idx]\n            I_B = b[idx]\n            \n            # LCA update with leakage and lateral inhibition\n            dA = I_A - leak * A_acc - inhibition * B_acc\n            dB = I_B - leak * B_acc - inhibition * A_acc\n            \n            A_acc = max(0.0, A_acc + dA)\n            B_acc = max(0.0, B_acc + dB)\n            \n            # Stop search if threshold is crossed\n            if A_acc >= threshold or B_acc >= threshold:\n                break\n                \n        scores = np.array([A_acc, B_acc])\n        z = beta * (scores - np.max(scores))\n        e = np.exp(z)\n        p_total += e / np.sum(e)\n        \n    p_core = p_total / n_sims\n    return (1.0 - epsilon) * p_core + epsilon * 0.5\n",
  "policy": "def policy(probabilities):\n    import numpy as np\n    probabilities = np.asarray(probabilities, dtype=np.float64)\n    probabilities /= probabilities.sum()\n    return int(np.random.choice(len(probabilities), p=probabilities))\n",
  "parameters": {
    "threshold": "[0.5, 5.0]",
    "leak": "[0.0, 0.5]",
    "inhibition": "[0.0, 0.5]",
    "beta": "[0.1, 10.0]",
    "epsilon": "[0.0, 0.5]",
    "max_steps": "{20, 50, 100}",
    "validities": "validities"
  },
  "rationale": "Following the arbiter's recommendation, this theory replaces the strict deterministic sequential search and the highly parameterized parallel recurrent network with a Probabilistic Leaky Competing Accumulator (LCA). Cues are sampled probabilistically proportional to their validities, and the evidence accumulates with leakage and mutual inhibition. The process stops when an accumulator hits a threshold or when `max_steps` is reached. To ensure smooth and stable probability estimates for the optimizer, the `predict` function runs 50 independent simulations of this stochastic process per trial and averages the resulting choice probabilities. This approach inherently captures both non-compensatory fast choices (when high-validity cues quickly drive an accumulator past the threshold) and compensatory tally-like behavior (when leakage prevents early stopping and multiple cues are aggregated over time)."
}
```
```

## Usage

```json
{
  "prompt_token_count": 13413,
  "candidates_token_count": 1015,
  "total_token_count": 16841
}
```
