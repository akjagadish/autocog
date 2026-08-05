# generation_iter_05_attempt_00

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
- THEORY 1 = `pi_8`
- THEORY 2 = `pi_12`
- The recommendation below acts on THEORY 2 (= `pi_12`).

Propose a brand-new theory that moves away from the 'dilution by averaging' paradigm. A promising direction is a 'Sequential Search with Evidence Accumulation and Decay' theory. In this theory, subjects evaluate cues in descending order of validity. Each active cue adds to an accumulator, but the subjective weight of each subsequent cue decays exponentially (or is discounted), meaning weak cues contribute very little to the decision rather than actively penalizing the strong cues. If the evidence difference between options reaches a threshold during the sequential search, a decision is made immediately (mimicking Take-The-Best); otherwise, it defaults to a decayed tally. This can explain the lack of dilution in some experiments (weak cues are just ignored) while still capturing bounded rationality.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_6` (overall score: 0.501)

**Description**
Dual-Process Strategy Selection Theory: Decision-makers probabilistically select between a non-compensatory heuristic (Take-The-Best) and a compensatory strategy (Weighted Additive, WADD) on a trial-by-trial basis. The probability of employing the non-compensatory heuristic is a logistic function of the absolute validity of the highest-ranking discriminating cue. When the top discriminating cue is highly valid, subjects are highly likely to rely solely on it (TTB). However, when the top discriminating cue is weak, confidence in the heuristic drops, and subjects fall back to integrating all available information (WADD).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    theta = float(parameters["theta"])
    tau = float(parameters["tau"])
    
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    top_cue = None
    for j in cue_order:
        if a[j] != b[j]:
            top_cue = j
            break
            
    if top_cue is None:
        p_mix = np.array([0.5, 0.5])
    else:
        v_top = val[top_cue]
        
        # Probability of using TTB is a logistic function of the top cue's validity
        p_ttb_use = 1.0 / (1.0 + np.exp(-tau * (v_top - theta)))
        
        # Take-The-Best (TTB) prediction
        winner_ttb = 0 if a[top_cue] > b[top_cue] else 1
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        z_ttb = beta * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
        # Weighted Additive (WADD) prediction
        score_a = np.sum(val * a)
        score_b = np.sum(val * b)
        scores_wadd = np.array([score_a, score_b])
        z_wadd = beta * (scores_wadd - np.max(scores_wadd))
        e_wadd = np.exp(z_wadd)
        p_wadd = e_wadd / np.sum(e_wadd)
        
        # Mix the two strategies based on the top cue validity
        p_mix = p_ttb_use * p_ttb + (1.0 - p_ttb_use) * p_wadd
        
    # Apply lapse rate
    return (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- theta: [0.0, 1.0]
- tau: [1.0, 100.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7581 (var=0.0332) vs this=0.7447 (var=0.0432)
- Experiment 2: real=0.2506 (var=0.0294) vs this=0.2217 (var=0.0293)
- Experiment 3: real=0.7236 (var=0.0302) vs this=0.8004 (var=0.0164)
- Experiment 4: real=0.3975 (var=0.0240) vs this=0.2433 (var=0.0289)
- Experiment 5: real=0.0574 (var=0.0093) vs this=0.0087 (var=0.0002)
- Experiment 6: real=0.0175 (var=0.0095) vs this=0.0012 (var=0.0149)
- Experiment 7: real=0.6875 (var=0.0691) vs this=0.0038 (var=0.0493)
- Experiment 8: real=0.0475 (var=0.1792) vs this=0.0092 (var=0.0047)
- Experiment 9: real=-0.7263 (var=0.0321) vs this=0.0568 (var=0.0274)
- Experiment 10: real=-0.0253 (var=0.2181) vs this=-0.1137 (var=0.0439)
- Experiment 11: real=0.0725 (var=0.0566) vs this=-0.0225 (var=0.0376)
- Experiment 12: real=-0.1700 (var=0.2061) vs this=-0.1537 (var=0.0647)
- Experiment 13: real=-0.6683 (var=0.0841) vs this=0.0508 (var=0.0190)
- Experiment 14: real=0.0100 (var=0.0081) vs this=-0.0025 (var=0.0118)
- Experiment 15: real=-0.0400 (var=0.0118) vs this=-0.0225 (var=0.0153)
- Experiment 16: real=0.0167 (var=0.0107) vs this=0.0250 (var=0.0093)
- Experiment 17: real=0.0000 (var=0.0000) vs this=0.0037 (var=0.0008)
- Experiment 18: real=0.5825 (var=0.0907) vs this=0.8025 (var=0.0289)
- Experiment 19: real=-0.0250 (var=0.0106) vs this=0.0267 (var=0.0089)
- Experiment 20: real=0.8386 (var=0.0093) vs this=0.3818 (var=0.0047)
- Experiment 21: real=0.0650 (var=0.0165) vs this=0.0250 (var=0.0224)
- Experiment 22: real=0.1768 (var=0.0184) vs this=0.8411 (var=0.0151)


---

### `pi_12` (overall score: 0.481)

**Description**
Threshold-Gated Dilution Theory: Decision-makers integrate cues differently depending on the number of active cues. When an option has only a few active cues (below a threshold), they are integrated additively (acting like a non-compensatory strategy if weights are steep). However, when a coalition of many cues is present, it triggers a shift to an averaging process, where the total evidence is diluted by the number of active cues. This explains why adding many weak cues to an option can paradoxically reduce its subjective value.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    lambda_val = float(parameters["lambda_val"])
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    tau = int(parameters["tau"])
    
    w = val ** lambda_val
    
    n_a = np.sum(a)
    n_b = np.sum(b)
    
    if n_a <= tau:
        v_a = np.sum(w * a)
    else:
        v_a = np.sum(w * a) / (n_a ** gamma)
        
    if n_b <= tau:
        v_b = np.sum(w * b)
    else:
        v_b = np.sum(w * b) / (n_b ** gamma)
        
    scores = np.array([v_a, v_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- lambda_val: [1.0, 20.0]
- gamma: [0.0, 10.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- tau: {1, 2, 3, 4}
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7581 (var=0.0332) vs this=0.6666 (var=0.0221)
- Experiment 2: real=0.2506 (var=0.0294) vs this=0.2903 (var=0.0275)
- Experiment 3: real=0.7236 (var=0.0302) vs this=0.7053 (var=0.0158)
- Experiment 4: real=0.3975 (var=0.0240) vs this=0.3079 (var=0.0141)
- Experiment 5: real=0.0574 (var=0.0093) vs this=0.0214 (var=0.0005)
- Experiment 6: real=0.0175 (var=0.0095) vs this=0.0588 (var=0.0529)
- Experiment 7: real=0.6875 (var=0.0691) vs this=0.2675 (var=0.0703)
- Experiment 8: real=0.0475 (var=0.1792) vs this=0.0250 (var=0.0078)
- Experiment 9: real=-0.7263 (var=0.0321) vs this=0.0379 (var=0.0690)
- Experiment 10: real=-0.0253 (var=0.2181) vs this=-0.2189 (var=0.0251)
- Experiment 11: real=0.0725 (var=0.0566) vs this=0.0725 (var=0.0914)
- Experiment 12: real=-0.1700 (var=0.2061) vs this=-0.1825 (var=0.0420)
- Experiment 13: real=-0.6683 (var=0.0841) vs this=-0.2967 (var=0.1275)
- Experiment 14: real=0.0100 (var=0.0081) vs this=-0.4017 (var=0.1075)
- Experiment 15: real=-0.0400 (var=0.0118) vs this=0.3475 (var=0.1117)
- Experiment 16: real=0.0167 (var=0.0107) vs this=0.1517 (var=0.1045)
- Experiment 17: real=0.0000 (var=0.0000) vs this=0.0022 (var=0.0010)
- Experiment 18: real=0.5825 (var=0.0907) vs this=0.7556 (var=0.0252)
- Experiment 19: real=-0.0250 (var=0.0106) vs this=-0.3117 (var=0.0801)
- Experiment 20: real=0.8386 (var=0.0093) vs this=0.7161 (var=0.0258)
- Experiment 21: real=0.0650 (var=0.0165) vs this=0.0208 (var=0.0852)
- Experiment 22: real=0.1768 (var=0.0184) vs this=0.7674 (var=0.0305)


---

### `pi_8` (overall score: 0.437)

**Description**
Evidence Dilution and Non-linear Weighting Theory (Validity-based Dilution with Amplified Penalty): Decision-makers evaluate options by integrating the validities of present features. However, instead of purely adding evidence, they partially average it. The presence of many low-validity features can paradoxically dilute the overall subjective value of an option (Evidence Dilution). This dilution is proportional to the sum of the validities of the present cues, and subjects apply a non-linear scaling to feature validities, amplifying the impact of the most valid cues. A potentially strong dilution penalty allows for severe subjective devaluation of options burdened with numerous weak features.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    lambda_val = float(parameters["lambda_val"])
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Non-linear weighting to capture TTB-like reliance on top cues
    w = val ** lambda_val
    
    # Dilute by the sum of validities of the present cues
    sum_val_a = np.sum(val * a)
    sum_val_b = np.sum(val * b)
    
    # Calculate subjective values with a dilution factor (gamma)
    v_a = np.sum(w * a) / (sum_val_a ** gamma) if sum_val_a > 0 else 0.0
    v_b = np.sum(w * b) / (sum_val_b ** gamma) if sum_val_b > 0 else 0.0
    
    scores = np.array([v_a, v_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- lambda_val: [1.0, 20.0]
- gamma: [0.0, 10.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7581 (var=0.0332) vs this=0.7484 (var=0.0105)
- Experiment 2: real=0.2506 (var=0.0294) vs this=0.3008 (var=0.0138)
- Experiment 3: real=0.7236 (var=0.0302) vs this=0.7111 (var=0.0112)
- Experiment 4: real=0.3975 (var=0.0240) vs this=0.3540 (var=0.0095)
- Experiment 5: real=0.0574 (var=0.0093) vs this=0.0296 (var=0.0012)
- Experiment 6: real=0.0175 (var=0.0095) vs this=-0.0200 (var=0.0366)
- Experiment 7: real=0.6875 (var=0.0691) vs this=0.3225 (var=0.0374)
- Experiment 8: real=0.0475 (var=0.1792) vs this=-0.0079 (var=0.0131)
- Experiment 9: real=-0.7263 (var=0.0321) vs this=-0.2421 (var=0.0811)
- Experiment 10: real=-0.0253 (var=0.2181) vs this=-0.1021 (var=0.0423)
- Experiment 11: real=0.0725 (var=0.0566) vs this=0.1388 (var=0.1325)
- Experiment 12: real=-0.1700 (var=0.2061) vs this=-0.0813 (var=0.0382)
- Experiment 13: real=-0.6683 (var=0.0841) vs this=-0.6167 (var=0.0803)
- Experiment 14: real=0.0100 (var=0.0081) vs this=-0.3458 (var=0.0815)
- Experiment 15: real=-0.0400 (var=0.0118) vs this=0.3963 (var=0.0946)
- Experiment 16: real=0.0167 (var=0.0107) vs this=-0.0100 (var=0.0446)
- Experiment 17: real=0.0000 (var=0.0000) vs this=-0.0108 (var=0.0005)
- Experiment 18: real=0.5825 (var=0.0907) vs this=0.7937 (var=0.0170)
- Experiment 19: real=-0.0250 (var=0.0106) vs this=-0.3858 (var=0.0991)
- Experiment 20: real=0.8386 (var=0.0093) vs this=0.6986 (var=0.0108)
- Experiment 21: real=0.0650 (var=0.0165) vs this=0.4192 (var=0.0785)
- Experiment 22: real=0.1768 (var=0.0184) vs this=0.5758 (var=0.0422)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.3125 -> ACCEPTED
- iter 2: loss=0.3068 -> ACCEPTED
- iter 3: loss=0.3215 -> REJECTED
- iter 4: loss=0.3149 -> REJECTED
- iter 5: loss=0.3501 -> REJECTED
Running-best (last ACCEPTED) base: iter 2 at loss=0.3068 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_match_count = 0
    disagree_count = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # TTB prediction
        ttb_winner = -1
        for j in range(len(a)):
            if a[j] > b[j]:
                ttb_winner = 0
                break
            elif b[j] > a[j]:
                ttb_winner = 1
                break
                
        # Tallying prediction
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = -1
            
        # Only consider trials where TTB and Tallying make opposite predictions
        if ttb_winner != -1 and tally_winner != -1 and ttb_winner != tally_winner:
            disagree_count += 1
            if row['response'] == ttb_winner:
                ttb_match_count += 1
                
    if disagree_count == 0:
        return 0.5
    return ttb_match_count / disagree_count

```

**Observed (real) value:** 0.7581 (var=0.0332)
**Previous candidate values (this loop):**
  - iter 1: 0.6150 (var=0.0537) (Δ vs real -0.1431)
  - iter 2: 0.7528 (var=0.0287) (Δ vs real -0.0053)
  - iter 3: 0.7916 (var=0.0365) (Δ vs real +0.0334)
  - iter 4: 0.7244 (var=0.0315) (Δ vs real -0.0338)
  - iter 5 (most recent): 0.7616 (var=0.0337) (Δ vs real +0.0034)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8391 (var=0.0094)
- pi_2: 0.1216 (var=0.0073)
- pi_3: 0.6753 (var=0.0250)
- pi_4: 0.6731 (var=0.0154)
- pi_5: 0.6447 (var=0.1186)
- pi_6: 0.7447 (var=0.0432)
- pi_7: 0.6416 (var=0.0448)
- pi_8: 0.7484 (var=0.0105)
- pi_9: 0.6731 (var=0.0252)
- pi_10: 0.7184 (var=0.0134)
- pi_11: 0.5975 (var=0.0257)
- pi_12: 0.6666 (var=0.0221)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]

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
        
        if a_wins > b_wins:
            tally_pref = 0
        elif b_wins > a_wins:
            tally_pref = 1
        else:
            continue
            
        matches.append(row['response'] == tally_pref)
        
    if len(matches) == 0:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.2506 (var=0.0294)
**Previous candidate values (this loop):**
  - iter 1: 0.3989 (var=0.0815) (Δ vs real +0.1483)
  - iter 2: 0.1861 (var=0.0253) (Δ vs real -0.0644)
  - iter 3: 0.1856 (var=0.0309) (Δ vs real -0.0650)
  - iter 4: 0.2047 (var=0.0185) (Δ vs real -0.0458)
  - iter 5 (most recent): 0.2097 (var=0.0326) (Δ vs real -0.0408)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8581 (var=0.0074)
- pi_1: 0.1211 (var=0.0091)
- pi_3: 0.2033 (var=0.0222)
- pi_4: 0.2844 (var=0.0129)
- pi_5: 0.2444 (var=0.0869)
- pi_6: 0.2217 (var=0.0293)
- pi_7: 0.3081 (var=0.0448)
- pi_8: 0.3008 (var=0.0138)
- pi_9: 0.2414 (var=0.0331)
- pi_10: 0.2583 (var=0.0162)
- pi_11: 0.3031 (var=0.0126)
- pi_12: 0.2903 (var=0.0275)

### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 1, 0, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.75, 0.65, 0.55])
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    diff = a_mat - b_mat
    
    # TTB prediction: heavily weights the first discriminating cue
    # Using powers of 10 ensures strict lexicographical ordering (TTB logic)
    weights = np.array([1000, 100, 10, 1])
    ttb_score = np.dot(diff, weights)
    ttb_pred = np.where(ttb_score > 0, 0, 1)
    
    # WADD prediction (with gamma=1, i.e., linear integration)
    wadd_score = np.dot(diff, val)
    wadd_pred = np.where(wadd_score > 0, 0, 1)
    
    # Identify trials where TTB and baseline WADD disagree
    divergent = ttb_pred != wadd_pred
    
    if not np.any(divergent):
        return 0.5
        
    responses = data['response'].values
    # Calculate proportion of choices matching TTB on these critical trials
    ttb_match = (responses[divergent] == ttb_pred[divergent]).mean()
    
    return float(ttb_match)
```

**Observed (real) value:** 0.7236 (var=0.0302)
**Previous candidate values (this loop):**
  - iter 1: 0.6289 (var=0.0361) (Δ vs real -0.0947)
  - iter 2: 0.8076 (var=0.0182) (Δ vs real +0.0840)
  - iter 3: 0.8289 (var=0.0171) (Δ vs real +0.1053)
  - iter 4: 0.7760 (var=0.0241) (Δ vs real +0.0524)
  - iter 5 (most recent): 0.7938 (var=0.0208) (Δ vs real +0.0702)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8418 (var=0.0111)
- pi_3: 0.7036 (var=0.0145)
- pi_2: 0.1582 (var=0.0129)
- pi_4: 0.6902 (var=0.0128)
- pi_5: 0.7213 (var=0.1024)
- pi_6: 0.8004 (var=0.0164)
- pi_7: 0.7058 (var=0.0359)
- pi_8: 0.7111 (var=0.0112)
- pi_9: 0.6898 (var=0.0209)
- pi_10: 0.7000 (var=0.0080)
- pi_11: 0.7089 (var=0.0150)
- pi_12: 0.7053 (var=0.0158)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float(data['response'].mean())
```

**Observed (real) value:** 0.3975 (var=0.0240)
**Previous candidate values (this loop):**
  - iter 1: 0.3698 (var=0.0519) (Δ vs real -0.0277)
  - iter 2: 0.2537 (var=0.0274) (Δ vs real -0.1438)
  - iter 3: 0.2431 (var=0.0337) (Δ vs real -0.1544)
  - iter 4: 0.2260 (var=0.0108) (Δ vs real -0.1715)
  - iter 5 (most recent): 0.2333 (var=0.0382) (Δ vs real -0.1642)
**Other theories' values on this metric (for reference):**
- pi_3: 0.3127 (var=0.0167)
- pi_1: 0.1787 (var=0.0150)
- pi_2: 0.8179 (var=0.0096)
- pi_4: 0.2710 (var=0.0132)
- pi_5: 0.3623 (var=0.0867)
- pi_6: 0.2433 (var=0.0289)
- pi_7: 0.3588 (var=0.0302)
- pi_8: 0.3540 (var=0.0095)
- pi_9: 0.3092 (var=0.0287)
- pi_10: 0.3696 (var=0.0059)
- pi_11: 0.2931 (var=0.0129)
- pi_12: 0.3079 (var=0.0141)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    data = data.copy()
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    # Trials 1, 2, and 3 are conflict trials where TTB prefers A and WADD prefers B.
    target_trials = ['10000', '01000', '10100']
    df_conflict = data[data['a_str'].isin(target_trials)].copy()
    df_conflict['chose_A'] = (df_conflict['response'] == 0).astype(float)
    
    subj_vars = []
    for subj, subj_df in df_conflict.groupby('subject_id'):
        means = subj_df.groupby('a_str')['chose_A'].mean()
        if len(means) == 3:
            subj_vars.append(means.var(ddof=1))
            
    if not subj_vars:
        return 0.0
        
    return float(np.mean(subj_vars))
```

**Observed (real) value:** 0.0574 (var=0.0093)
**Previous candidate values (this loop):**
  - iter 1: 0.0303 (var=0.0018) (Δ vs real -0.0271)
  - iter 2: 0.0234 (var=0.0025) (Δ vs real -0.0340)
  - iter 3: 0.0306 (var=0.0040) (Δ vs real -0.0268)
  - iter 4: 0.0337 (var=0.0040) (Δ vs real -0.0237)
  - iter 5 (most recent): 0.0123 (var=0.0006) (Δ vs real -0.0451)
**Other theories' values on this metric (for reference):**
- pi_4: 0.0096 (var=0.0001)
- pi_3: 0.0331 (var=0.0015)
- pi_1: 0.0040 (var=0.0000)
- pi_2: 0.0061 (var=0.0000)
- pi_5: 0.0237 (var=0.0046)
- pi_6: 0.0087 (var=0.0002)
- pi_7: 0.0177 (var=0.0003)
- pi_8: 0.0296 (var=0.0012)
- pi_9: 0.0159 (var=0.0004)
- pi_10: 0.0276 (var=0.0005)
- pi_11: 0.0517 (var=0.0049)
- pi_12: 0.0214 (var=0.0005)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    data['chose_A'] = 1 - data['response']
    
    t2_mask = (data['A_str'] == '10001') & (data['B_str'] == '01100')
    t5_mask = (data['A_str'] == '01001') & (data['B_str'] == '00110')
    
    p_a_t2 = data[t2_mask]['chose_A'].mean() if t2_mask.sum() > 0 else 0.5
    p_a_t5 = data[t5_mask]['chose_A'].mean() if t5_mask.sum() > 0 else 0.5
    
    return float(p_a_t2 - p_a_t5)
```

**Observed (real) value:** 0.0175 (var=0.0095)
**Previous candidate values (this loop):**
  - iter 1: 0.0625 (var=0.0484) (Δ vs real +0.0450)
  - iter 2: 0.0500 (var=0.0623) (Δ vs real +0.0325)
  - iter 3: 0.1088 (var=0.0542) (Δ vs real +0.0913)
  - iter 4: 0.3750 (var=0.1453) (Δ vs real +0.3575)
  - iter 5 (most recent): 0.1138 (var=0.0315) (Δ vs real +0.0963)
**Other theories' values on this metric (for reference):**
- pi_3: 0.1713 (var=0.0375)
- pi_4: -0.0338 (var=0.0268)
- pi_1: 0.0162 (var=0.0131)
- pi_2: 0.0150 (var=0.0245)
- pi_5: -0.0250 (var=0.0333)
- pi_6: 0.0012 (var=0.0149)
- pi_7: 0.0725 (var=0.0232)
- pi_8: -0.0200 (var=0.0366)
- pi_9: 0.0463 (var=0.0367)
- pi_10: -0.0350 (var=0.0336)
- pi_11: 0.0600 (var=0.0187)
- pi_12: 0.0588 (var=0.0529)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_seq = data['option_a_ratings'].apply(tuple)
    b_seq = data['option_b_ratings'].apply(tuple)
    
    t1_a = (1, 0, 0, 0, 0)
    t1_b = (0, 1, 1, 1, 1)
    
    t4_a = (1, 1, 1, 1, 0)
    t4_b = (1, 1, 1, 0, 1)
    
    t1_mask1 = (a_seq == t1_a) & (b_seq == t1_b)
    t1_mask2 = (a_seq == t1_b) & (b_seq == t1_a)
    
    t4_mask1 = (a_seq == t4_a) & (b_seq == t4_b)
    t4_mask2 = (a_seq == t4_b) & (b_seq == t4_a)
    
    p_t1 = 0.0
    n_t1 = t1_mask1.sum() + t1_mask2.sum()
    if n_t1 > 0:
        chose_a_t1 = (t1_mask1 & (data['response'] == 0)) | (t1_mask2 & (data['response'] == 1))
        p_t1 = chose_a_t1.sum() / n_t1
        
    p_t4 = 0.0
    n_t4 = t4_mask1.sum() + t4_mask2.sum()
    if n_t4 > 0:
        chose_a_t4 = (t4_mask1 & (data['response'] == 0)) | (t4_mask2 & (data['response'] == 1))
        p_t4 = chose_a_t4.sum() / n_t4
        
    return float(p_t1 - p_t4)
```

**Observed (real) value:** 0.6875 (var=0.0691)
**Previous candidate values (this loop):**
  - iter 1: -0.0200 (var=0.1919) (Δ vs real -0.7075)
  - iter 2: 0.2500 (var=0.1183) (Δ vs real -0.4375)
  - iter 3: 0.3062 (var=0.0829) (Δ vs real -0.3813)
  - iter 4: 0.4450 (var=0.0878) (Δ vs real -0.2425)
  - iter 5 (most recent): 0.2163 (var=0.0641) (Δ vs real -0.4712)
**Other theories' values on this metric (for reference):**
- pi_5: -0.1338 (var=0.1275)
- pi_3: 0.2250 (var=0.0842)
- pi_1: -0.0088 (var=0.0205)
- pi_2: -0.3850 (var=0.0235)
- pi_4: -0.1412 (var=0.0218)
- pi_6: 0.0038 (var=0.0493)
- pi_7: 0.0450 (var=0.1074)
- pi_8: 0.3225 (var=0.0374)
- pi_9: 0.2762 (var=0.1014)
- pi_10: 0.3413 (var=0.0397)
- pi_11: -0.1675 (var=0.0433)
- pi_12: 0.2675 (var=0.0703)

### Experiment 8
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    data['trial_str'] = data.apply(lambda row: ''.join(map(str, row['option_a_ratings'])) + '_' + ''.join(map(str, row['option_b_ratings'])), axis=1)
    
    t1 = '110000_001111'
    t2 = '001111_110000'
    t3 = '101000_010111'
    t4 = '010111_101000'
    
    data['chose_a'] = (data['response'] == 0).astype(float)
    subj_means = data.groupby(['subject_id', 'trial_str'])['chose_a'].mean().unstack()
    
    # Preference for the option with the top cue in Trial 1/2 vs Trial 3/4
    if t1 in subj_means.columns and t2 in subj_means.columns:
        pref_1 = (subj_means[t1] + (1.0 - subj_means[t2])) / 2.0
    else:
        return 0.0
        
    if t3 in subj_means.columns and t4 in subj_means.columns:
        pref_3 = (subj_means[t3] + (1.0 - subj_means[t4])) / 2.0
    else:
        return 0.0
        
    diff = pref_1 - pref_3
    
    if isinstance(diff, pd.Series):
        return float(diff.mean())
    return float(diff)
```

**Observed (real) value:** 0.0475 (var=0.1792)
**Previous candidate values (this loop):**
  - iter 1: 0.0800 (var=0.0441) (Δ vs real +0.0325)
  - iter 2: 0.0104 (var=0.0160) (Δ vs real -0.0371)
  - iter 3: -0.1050 (var=0.0933) (Δ vs real -0.1525)
  - iter 4: -0.0558 (var=0.0291) (Δ vs real -0.1033)
  - iter 5 (most recent): 0.0183 (var=0.0289) (Δ vs real -0.0292)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0346 (var=0.0103)
- pi_5: 0.3017 (var=0.1821)
- pi_1: -0.0063 (var=0.0057)
- pi_2: 0.0025 (var=0.0051)
- pi_4: 0.0071 (var=0.0095)
- pi_6: 0.0092 (var=0.0047)
- pi_7: 0.0938 (var=0.0070)
- pi_8: -0.0079 (var=0.0131)
- pi_9: 0.0721 (var=0.0127)
- pi_10: 0.0067 (var=0.0102)
- pi_11: 0.0596 (var=0.0081)
- pi_12: 0.0250 (var=0.0078)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    
    def get_pA(a_str, b_str):
        mask1 = (data['A_str'] == a_str) & (data['B_str'] == b_str)
        mask2 = (data['A_str'] == b_str) & (data['B_str'] == a_str)
        chose_A = 0
        total = 0
        if mask1.sum() > 0:
            chose_A += (data.loc[mask1, 'response'] == 0).sum()
            total += mask1.sum()
        if mask2.sum() > 0:
            chose_A += (data.loc[mask2, 'response'] == 1).sum()
            total += mask2.sum()
        return chose_A / total if total > 0 else 0.5

    # Trial 1: Top cue (0.90) vs single opposing cue (0.85)
    pA_t1 = get_pA("10000", "01000")
    
    # Trial 4: Top cue (0.90) vs coalition of 4 opposing cues (0.85 + 0.80 + 0.75 + 0.70)
    pA_t4 = get_pA("10000", "01111")
    
    return float(pA_t1 - pA_t4)

```

**Observed (real) value:** -0.7263 (var=0.0321)
**Previous candidate values (this loop):**
  - iter 1: 0.2621 (var=0.0980) (Δ vs real +0.9884)
  - iter 2: 0.0453 (var=0.0691) (Δ vs real +0.7716)
  - iter 3: 0.0274 (var=0.0624) (Δ vs real +0.7537)
  - iter 4: 0.0158 (var=0.0240) (Δ vs real +0.7421)
  - iter 5 (most recent): 0.0042 (var=0.0336) (Δ vs real +0.7305)
**Other theories' values on this metric (for reference):**
- pi_6: 0.0568 (var=0.0274)
- pi_3: 0.2379 (var=0.0708)
- pi_1: 0.0095 (var=0.0097)
- pi_2: 0.3484 (var=0.0173)
- pi_4: 0.1189 (var=0.0240)
- pi_5: 0.1653 (var=0.0859)
- pi_7: 0.2232 (var=0.0400)
- pi_8: -0.2421 (var=0.0811)
- pi_9: -0.0516 (var=0.0436)
- pi_10: -0.0526 (var=0.0709)
- pi_11: 0.3421 (var=0.0666)
- pi_12: 0.0379 (var=0.0690)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify Trial 1 and Trial 3 based on option A's ratings
    t1_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 0, 0))
    t3_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 0, 0))
    
    if t1_mask.sum() == 0 or t3_mask.sum() == 0:
        return 0.0
        
    # response is 0 for A, 1 for B. So mean() is the proportion of choosing B.
    # We want the difference in proportion of choosing A: P(A | Trial 3) - P(A | Trial 1)
    # Which is (1 - m3) - (1 - m1) = m1 - m3
    m1 = data[t1_mask]['response'].mean()
    m3 = data[t3_mask]['response'].mean()
    
    return float(m1 - m3)
```

**Observed (real) value:** -0.0253 (var=0.2181)
**Previous candidate values (this loop):**
  - iter 1: -0.1779 (var=0.0382) (Δ vs real -0.1526)
  - iter 2: -0.0726 (var=0.0463) (Δ vs real -0.0474)
  - iter 3: -0.1063 (var=0.0717) (Δ vs real -0.0811)
  - iter 4: -0.0421 (var=0.0341) (Δ vs real -0.0168)
  - iter 5 (most recent): -0.0137 (var=0.0271) (Δ vs real +0.0116)
**Other theories' values on this metric (for reference):**
- pi_3: -0.3021 (var=0.0367)
- pi_6: -0.1137 (var=0.0439)
- pi_1: -0.0158 (var=0.0083)
- pi_2: 0.0211 (var=0.0081)
- pi_4: 0.0084 (var=0.0218)
- pi_5: -0.1484 (var=0.0951)
- pi_7: -0.0768 (var=0.0133)
- pi_8: -0.1021 (var=0.0423)
- pi_9: -0.1421 (var=0.0301)
- pi_10: -0.1084 (var=0.0352)
- pi_11: -0.2589 (var=0.0503)
- pi_12: -0.2189 (var=0.0251)

### Experiment 11
**Design**
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['a_key'] = data['option_a_ratings'].apply(tuple)
    
    # response == 0 means Option A was chosen, so 1 - mean(response) is P(A)
    p_A = 1.0 - data.groupby('a_key')['response'].mean()
    
    # Trials without the shared top cue
    t1 = p_A.get((0, 1, 1, 0, 0), 0.5)
    t3 = p_A.get((0, 1, 0, 0, 0), 0.5)
    t5 = p_A.get((0, 1, 1, 1, 0), 0.5)
    
    # Trials with the shared top cue (Cue 0 = 1 for both options)
    t2 = p_A.get((1, 1, 1, 0, 0), 0.5)
    t4 = p_A.get((1, 1, 0, 0, 0), 0.5)
    t6 = p_A.get((1, 1, 1, 1, 0), 0.5)
    
    # Calculate the regression to chance (0.5) caused by the shared top cue
    diff1 = abs(t1 - 0.5) - abs(t2 - 0.5)
    diff2 = abs(t3 - 0.5) - abs(t4 - 0.5)
    diff3 = abs(t5 - 0.5) - abs(t6 - 0.5)
    
    return float(diff1 + diff2 + diff3)
```

**Observed (real) value:** 0.0725 (var=0.0566)
**Previous candidate values (this loop):**
  - iter 1: 0.0238 (var=0.0569) (Δ vs real -0.0487)
  - iter 2: -0.0237 (var=0.0440) (Δ vs real -0.0963)
  - iter 3: 0.0375 (var=0.0581) (Δ vs real -0.0350)
  - iter 4: 0.0250 (var=0.0392) (Δ vs real -0.0475)
  - iter 5 (most recent): -0.0188 (var=0.0441) (Δ vs real -0.0913)
**Other theories' values on this metric (for reference):**
- pi_7: 0.1062 (var=0.0608)
- pi_3: -0.0700 (var=0.0394)
- pi_1: 0.0025 (var=0.0245)
- pi_2: 0.0100 (var=0.0298)
- pi_4: -0.0675 (var=0.0434)
- pi_5: 0.0125 (var=0.0183)
- pi_6: -0.0225 (var=0.0376)
- pi_8: 0.1388 (var=0.1325)
- pi_9: 0.4700 (var=0.1624)
- pi_10: 0.1950 (var=0.1038)
- pi_11: -0.0150 (var=0.0388)
- pi_12: 0.0725 (var=0.0914)

### Experiment 12
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    mask_t6 = (data['A_str'] == '00100') & (data['B_str'] == '00011')
    mask_t1 = (data['A_str'] == '10000') & (data['B_str'] == '01111')
    
    p_a_t6 = (data[mask_t6]['response'] == 0).mean() if mask_t6.sum() > 0 else 0.5
    p_a_t1 = (data[mask_t1]['response'] == 0).mean() if mask_t1.sum() > 0 else 0.5
    
    return float(p_a_t6 - p_a_t1)
```

**Observed (real) value:** -0.1700 (var=0.2061)
**Previous candidate values (this loop):**
  - iter 1: -0.1338 (var=0.0634) (Δ vs real +0.0362)
  - iter 2: -0.0400 (var=0.0506) (Δ vs real +0.1300)
  - iter 3: -0.1050 (var=0.1035) (Δ vs real +0.0650)
  - iter 4: -0.0962 (var=0.0507) (Δ vs real +0.0737)
  - iter 5 (most recent): 0.0375 (var=0.0464) (Δ vs real +0.2075)
**Other theories' values on this metric (for reference):**
- pi_3: -0.1988 (var=0.0731)
- pi_7: 0.0025 (var=0.0330)
- pi_1: 0.0100 (var=0.0154)
- pi_2: 0.0400 (var=0.0159)
- pi_4: -0.0063 (var=0.0216)
- pi_5: -0.1063 (var=0.1088)
- pi_6: -0.1537 (var=0.0647)
- pi_8: -0.0813 (var=0.0382)
- pi_9: -0.0475 (var=0.0377)
- pi_10: -0.0613 (var=0.0196)
- pi_11: 0.0325 (var=0.0360)
- pi_12: -0.1825 (var=0.0420)

### Experiment 13
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    is_t2 = (a_sums == 4) & (b_sums == 1)
    is_t3 = (a_sums == 1) & (b_sums == 4)
    
    # Probability of choosing A
    p_a_t2 = 1.0 - data.loc[is_t2, 'response'].mean()
    p_a_t3 = 1.0 - data.loc[is_t3, 'response'].mean()
    
    return float(p_a_t2 - p_a_t3)
```

**Observed (real) value:** -0.6683 (var=0.0841)
**Previous candidate values (this loop):**
  - iter 1: 0.2000 (var=0.1328) (Δ vs real +0.8683)
  - iter 2: -0.5225 (var=0.2022) (Δ vs real +0.1458)
  - iter 3: -0.5083 (var=0.1399) (Δ vs real +0.1600)
  - iter 4: -0.2867 (var=0.2012) (Δ vs real +0.3817)
  - iter 5 (most recent): -0.4117 (var=0.1618) (Δ vs real +0.2567)
**Other theories' values on this metric (for reference):**
- pi_8: -0.6167 (var=0.0803)
- pi_3: 0.1117 (var=0.0646)
- pi_1: -0.0108 (var=0.0103)
- pi_2: 0.7508 (var=0.0378)
- pi_4: 0.1417 (var=0.0210)
- pi_5: 0.2633 (var=0.1674)
- pi_6: 0.0508 (var=0.0190)
- pi_7: 0.0867 (var=0.0485)
- pi_9: -0.0517 (var=0.0619)
- pi_10: -0.5883 (var=0.0700)
- pi_11: 0.3275 (var=0.0596)
- pi_12: -0.2967 (var=0.1275)

### Experiment 14
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_keys = data['option_a_ratings'].apply(tuple)
    b_keys = data['option_b_ratings'].apply(tuple)
    
    t1_mask = (a_keys == (1, 0, 0, 0, 0)) & (b_keys == (0, 1, 0, 0, 0))
    t2_mask = (a_keys == (1, 0, 1, 1, 1)) & (b_keys == (0, 1, 0, 0, 0))
    
    p_a_t1 = (data.loc[t1_mask, 'response'] == 0).mean()
    p_a_t2 = (data.loc[t2_mask, 'response'] == 0).mean()
    
    return float(p_a_t2 - p_a_t1)
```

**Observed (real) value:** 0.0100 (var=0.0081)
**Previous candidate values (this loop):**
  - iter 1: 0.0533 (var=0.0172) (Δ vs real +0.0433)
  - iter 2: -0.3575 (var=0.1263) (Δ vs real -0.3675)
  - iter 3: -0.4267 (var=0.1163) (Δ vs real -0.4367)
  - iter 4: -0.3775 (var=0.1608) (Δ vs real -0.3875)
  - iter 5 (most recent): -0.4108 (var=0.1512) (Δ vs real -0.4208)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0333 (var=0.0132)
- pi_8: -0.3458 (var=0.0815)
- pi_1: 0.0158 (var=0.0097)
- pi_2: 0.3500 (var=0.0331)
- pi_4: 0.0592 (var=0.0170)
- pi_5: 0.0817 (var=0.0290)
- pi_6: -0.0025 (var=0.0118)
- pi_7: 0.0267 (var=0.0263)
- pi_9: -0.0725 (var=0.0503)
- pi_10: -0.5333 (var=0.0687)
- pi_11: 0.0017 (var=0.0098)
- pi_12: -0.4017 (var=0.1075)

### Experiment 15
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Extract A's features as strings for easy matching
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A = [1, 0, 0, 0, 0]
    # Trial 2: A = [1, 0, 1, 1, 1]
    # Response is 0 if A, 1 if B. We want P(Choose A), which is 1.0 - response.mean()
    
    t1_data = data[a_str == '10000']
    t2_data = data[a_str == '10111']
    
    if len(t1_data) == 0 or len(t2_data) == 0:
        return 0.0
        
    prob_a_t1 = 1.0 - t1_data['response'].mean()
    prob_a_t2 = 1.0 - t2_data['response'].mean()
    
    return float(prob_a_t1 - prob_a_t2)
```

**Observed (real) value:** -0.0400 (var=0.0118)
**Previous candidate values (this loop):**
  - iter 1: -0.0262 (var=0.0170) (Δ vs real +0.0138)
  - iter 2: 0.3287 (var=0.1665) (Δ vs real +0.3688)
  - iter 3: 0.4712 (var=0.1330) (Δ vs real +0.5112)
  - iter 4: 0.3250 (var=0.1298) (Δ vs real +0.3650)
  - iter 5 (most recent): 0.4413 (var=0.1279) (Δ vs real +0.4813)
**Other theories' values on this metric (for reference):**
- pi_8: 0.3963 (var=0.0946)
- pi_9: 0.0625 (var=0.0509)
- pi_1: 0.0113 (var=0.0146)
- pi_2: -0.3688 (var=0.0227)
- pi_3: -0.0138 (var=0.0240)
- pi_4: -0.0737 (var=0.0145)
- pi_5: -0.0637 (var=0.0279)
- pi_6: -0.0225 (var=0.0153)
- pi_7: -0.0550 (var=0.0239)
- pi_10: 0.5263 (var=0.0914)
- pi_11: -0.0225 (var=0.0156)
- pi_12: 0.3475 (var=0.1117)

### Experiment 16
**Design**
  A=[0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, map(int, x))))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, map(int, x))))
    
    trial_3_mask = (data['A_str'] == '10011') & (data['B_str'] == '01000')
    trial_1_mask = (data['A_str'] == '00011') & (data['B_str'] == '00010')
    
    p_a_3 = 1.0 - data.loc[trial_3_mask, 'response'].mean() if trial_3_mask.sum() > 0 else 0.5
    p_a_1 = 1.0 - data.loc[trial_1_mask, 'response'].mean() if trial_1_mask.sum() > 0 else 0.5
    
    return float(p_a_3 - p_a_1)
```

**Observed (real) value:** 0.0167 (var=0.0107)
**Previous candidate values (this loop):**
  - iter 1: 0.2558 (var=0.0372) (Δ vs real +0.2392)
  - iter 2: 0.2167 (var=0.0788) (Δ vs real +0.2000)
  - iter 3: 0.1158 (var=0.0793) (Δ vs real +0.0992)
  - iter 4: 0.2958 (var=0.1081) (Δ vs real +0.2792)
  - iter 5 (most recent): 0.2442 (var=0.0965) (Δ vs real +0.2275)
**Other theories' values on this metric (for reference):**
- pi_9: 0.2992 (var=0.0728)
- pi_8: -0.0100 (var=0.0446)
- pi_1: -0.0133 (var=0.0114)
- pi_2: 0.0067 (var=0.0110)
- pi_3: 0.2992 (var=0.0266)
- pi_4: 0.0058 (var=0.0078)
- pi_5: 0.0283 (var=0.0087)
- pi_6: 0.0250 (var=0.0093)
- pi_7: 0.2233 (var=0.0364)
- pi_10: -0.1583 (var=0.0413)
- pi_11: 0.0525 (var=0.0151)
- pi_12: 0.1517 (var=0.1045)

### Experiment 17
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['b_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1_mask = (data['a_str'] == '10100') & (data['b_str'] == '01010')
    t2_mask = (data['a_str'] == '10001') & (data['b_str'] == '01010')
    
    def subj_metric(df):
        t1_resp = df.loc[t1_mask, 'response']
        t2_resp = df.loc[t2_mask, 'response']
        if len(t1_resp) == 0 or len(t2_resp) == 0:
            return 0.0
            
        p_a_t1 = (t1_resp == 0).mean()
        p_a_t2 = (t2_resp == 0).mean()
        
        # Weight by the subject's signal-to-noise ratio measured via T2.
        weight = max(0.0, p_a_t2 - 0.5)
        return float(weight * (p_a_t1 - p_a_t2))
        
    return float(data.groupby('subject_id').apply(subj_metric).mean())
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1: -0.0032 (var=0.0008) (Δ vs real -0.0032)
  - iter 2: -0.0007 (var=0.0009) (Δ vs real -0.0007)
  - iter 3: 0.0034 (var=0.0009) (Δ vs real +0.0034)
  - iter 4: 0.0044 (var=0.0009) (Δ vs real +0.0044)
  - iter 5 (most recent): 0.0008 (var=0.0006) (Δ vs real +0.0008)
**Other theories' values on this metric (for reference):**
- pi_8: -0.0108 (var=0.0005)
- pi_10: -0.0003 (var=0.0002)
- pi_1: -0.0052 (var=0.0009)
- pi_2: -0.0029 (var=0.0001)
- pi_3: -0.0008 (var=0.0013)
- pi_4: 0.0040 (var=0.0009)
- pi_5: 0.0017 (var=0.0006)
- pi_6: 0.0037 (var=0.0008)
- pi_7: -0.0062 (var=0.0005)
- pi_9: -0.0099 (var=0.0012)
- pi_11: -0.0024 (var=0.0009)
- pi_12: 0.0022 (var=0.0010)

### Experiment 18
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(str(int(v)) for v in x))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(str(int(v)) for v in x))
    
    # Trial 2: A=[0, 1, 0, 0, 0] (sum=0.9), B=[0, 0, 1, 1, 0] (sum=1.0)
    t2 = (a_str == '01000') & (b_str == '00110')
    # Trial 6: A=[0, 1, 0, 0, 0] (sum=0.9), B=[0, 0, 1, 1, 1] (sum=1.5)
    t6 = (a_str == '01000') & (b_str == '00111')
    
    target_trials = t2 | t6
    if not target_trials.any():
        return 0.5
        
    return float((data.loc[target_trials, 'response'] == 0).mean())
```

**Observed (real) value:** 0.5825 (var=0.0907)
**Previous candidate values (this loop):**
  - iter 1: 0.6488 (var=0.0365) (Δ vs real +0.0663)
  - iter 2: 0.8356 (var=0.0198) (Δ vs real +0.2531)
  - iter 3: 0.7700 (var=0.0521) (Δ vs real +0.1875)
  - iter 4: 0.6581 (var=0.0885) (Δ vs real +0.0756)
  - iter 5 (most recent): 0.8325 (var=0.0181) (Δ vs real +0.2500)
**Other theories' values on this metric (for reference):**
- pi_10: 0.8144 (var=0.0167)
- pi_8: 0.7937 (var=0.0170)
- pi_1: 0.8306 (var=0.0102)
- pi_2: 0.1400 (var=0.0094)
- pi_3: 0.6894 (var=0.0189)
- pi_4: 0.6919 (var=0.0231)
- pi_5: 0.7625 (var=0.1062)
- pi_6: 0.8025 (var=0.0289)
- pi_7: 0.8063 (var=0.0314)
- pi_9: 0.8325 (var=0.0159)
- pi_11: 0.5956 (var=0.0304)
- pi_12: 0.7556 (var=0.0252)

### Experiment 19
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1 = data[(data['A_str'] == '10000') & (data['B_str'] == '01000')]
    t2 = data[(data['A_str'] == '10111') & (data['B_str'] == '01000')]
    
    p_a_t1 = 1.0 - t1['response'].mean() if len(t1) > 0 else 0.5
    p_a_t2 = 1.0 - t2['response'].mean() if len(t2) > 0 else 0.5
    
    return float(p_a_t2 - p_a_t1)
```

**Observed (real) value:** -0.0250 (var=0.0106)
**Previous candidate values (this loop):**
  - iter 1: 0.0167 (var=0.0124) (Δ vs real +0.0417)
  - iter 2: -0.3908 (var=0.1378) (Δ vs real -0.3658)
  - iter 3: -0.5000 (var=0.1181) (Δ vs real -0.4750)
  - iter 4: -0.2917 (var=0.1253) (Δ vs real -0.2667)
  - iter 5 (most recent): -0.4517 (var=0.1313) (Δ vs real -0.4267)
**Other theories' values on this metric (for reference):**
- pi_8: -0.3858 (var=0.0991)
- pi_11: 0.0150 (var=0.0113)
- pi_1: 0.0100 (var=0.0131)
- pi_2: 0.3583 (var=0.0159)
- pi_3: 0.0267 (var=0.0121)
- pi_4: 0.0100 (var=0.0089)
- pi_5: 0.0525 (var=0.0159)
- pi_6: 0.0267 (var=0.0089)
- pi_7: 0.0392 (var=0.0215)
- pi_9: -0.0275 (var=0.0267)
- pi_10: -0.5283 (var=0.0741)
- pi_12: -0.3117 (var=0.0801)

### Experiment 20
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option A has many cues (including the top ones) and Option B has few cues
    # Trial 2: A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
    # Trial 4: A=[1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
    mask = data['option_a_ratings'].apply(lambda x: sum(x) >= 4) & data['option_b_ratings'].apply(lambda x: sum(x) <= 2)
    # Return the proportion of times Option B was chosen
    return float(data[mask]['response'].mean())
```

**Observed (real) value:** 0.8386 (var=0.0093)
**Previous candidate values (this loop):**
  - iter 1: 0.3723 (var=0.0198) (Δ vs real -0.4663)
  - iter 2: 0.6747 (var=0.0507) (Δ vs real -0.1639)
  - iter 3: 0.7126 (var=0.0478) (Δ vs real -0.1260)
  - iter 4: 0.7309 (var=0.0356) (Δ vs real -0.1077)
  - iter 5 (most recent): 0.7158 (var=0.0511) (Δ vs real -0.1228)
**Other theories' values on this metric (for reference):**
- pi_11: 0.2684 (var=0.0100)
- pi_8: 0.6986 (var=0.0108)
- pi_1: 0.3747 (var=0.0032)
- pi_2: 0.1196 (var=0.0072)
- pi_3: 0.4407 (var=0.0174)
- pi_4: 0.3316 (var=0.0055)
- pi_5: 0.3161 (var=0.0175)
- pi_6: 0.3818 (var=0.0047)
- pi_7: 0.3937 (var=0.0140)
- pi_9: 0.5849 (var=0.0232)
- pi_10: 0.7386 (var=0.0240)
- pi_12: 0.7161 (var=0.0258)

### Experiment 21
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate the number of active cues in Option A
    n_cues = data['option_a_ratings'].apply(sum)
    
    # Calculate the probability of choosing A for each number of cues
    p_a = 1.0 - data.groupby(n_cues)['response'].mean()
    
    # Ensure we have data for all 4 cue levels
    if not all(k in p_a for k in [1, 2, 3, 4]):
        return 0.0
        
    # Calculate consecutive differences in P(A)
    diffs = [p_a[k+1] - p_a[k] for k in [1, 2, 3]]
    
    # The metric is the difference between the maximum increase and the maximum decrease
    # Competing theory predicts a steady increase followed by a sharp drop (large max - min)
    # Advocated theory predicts a smooth curve with less extreme fluctuations in differences
    return float(np.max(diffs) - np.min(diffs))
```

**Observed (real) value:** 0.0650 (var=0.0165)
**Previous candidate values (this loop):**
  - iter 1: 0.0758 (var=0.0125) (Δ vs real +0.0108)
  - iter 2: 0.0942 (var=0.0675) (Δ vs real +0.0292)
  - iter 3: 0.1258 (var=0.0686) (Δ vs real +0.0608)
  - iter 4: 0.0250 (var=0.0825) (Δ vs real -0.0400)
  - iter 5 (most recent): 0.0825 (var=0.0709) (Δ vs real +0.0175)
**Other theories' values on this metric (for reference):**
- pi_8: 0.4192 (var=0.0785)
- pi_12: 0.0208 (var=0.0852)
- pi_1: 0.0500 (var=0.0132)
- pi_2: 0.3583 (var=0.0301)
- pi_3: 0.0467 (var=0.0172)
- pi_4: 0.0667 (var=0.0136)
- pi_5: 0.0808 (var=0.0197)
- pi_6: 0.0250 (var=0.0224)
- pi_7: 0.0558 (var=0.0138)
- pi_9: 0.0683 (var=0.0239)
- pi_10: 0.4750 (var=0.0580)
- pi_11: 0.0242 (var=0.0117)

### Experiment 22
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    mask1 = (a_str == '110000') & (b_str == '001100')
    mask2 = (a_str == '001100') & (b_str == '110000')
    
    valid = mask1 | mask2
    if not valid.any():
        return 0.5
        
    subset = data[valid]
    m1 = mask1[valid]
    
    chose_A = np.where(m1, subset['response'] == 0, subset['response'] == 1)
    
    return float(np.mean(chose_A))
```

**Observed (real) value:** 0.1768 (var=0.0184)
**Previous candidate values (this loop):**
  - iter 1: 0.8642 (var=0.0124) (Δ vs real +0.6874)
  - iter 2: 0.8442 (var=0.0265) (Δ vs real +0.6674)
  - iter 3: 0.7884 (var=0.0567) (Δ vs real +0.6116)
  - iter 4: 0.7916 (var=0.0285) (Δ vs real +0.6147)
  - iter 5 (most recent): 0.8242 (var=0.0199) (Δ vs real +0.6474)
**Other theories' values on this metric (for reference):**
- pi_12: 0.7674 (var=0.0305)
- pi_8: 0.5758 (var=0.0422)
- pi_1: 0.8474 (var=0.0160)
- pi_2: 0.5042 (var=0.0114)
- pi_3: 0.8284 (var=0.0195)
- pi_4: 0.8411 (var=0.0168)
- pi_5: 0.9084 (var=0.0186)
- pi_6: 0.8411 (var=0.0151)
- pi_7: 0.7958 (var=0.0203)
- pi_9: 0.8242 (var=0.0180)
- pi_10: 0.6379 (var=0.0312)
- pi_11: 0.8474 (var=0.0111)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Sequential Search with Evidence Accumulation, Decay, and Cue Cost: Decision-makers evaluate cues in descending order of validity. Each active cue adds to an evidence accumulator, but the subjective weight of each subsequent cue decays exponentially. Additionally, there is a fixed cognitive or evaluative cost associated with processing each present cue. For highly valid cues, the weight exceeds the cost, adding to the option's value. However, for weak cues (where the decayed weight is lower than the cost), evaluating the cue actively penalizes the option, capturing strong dilution effects. If the absolute difference in accumulated evidence reaches a subjective threshold during the sequential search, a decision is made immediately.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    decay = float(parameters["decay"])
    threshold = float(parameters["threshold"])
    cue_cost = float(parameters["cue_cost"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Sort cues by validity in descending order
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    acc_a = 0.0
    acc_b = 0.0
    
    # Evaluate cues sequentially
    for k, j in enumerate(cue_order):
        # Exponential decay of subjective weight based on cue rank
        weight = val[j] * (decay ** k)
        
        # Add weight minus cue cost for each active cue
        if a[j] == 1:
            acc_a += weight - cue_cost
        if b[j] == 1:
            acc_b += weight - cue_cost
        
        # Early stopping if the evidence difference reaches the threshold
        if abs(acc_a - acc_b) >= threshold:
            break
            
    scores = np.array([acc_a, acc_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- decay: [0.0, 1.0]
- threshold: [0.0, 5.0]
- cue_cost: [0.0, 1.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`: To address the critic's feedback regarding the model's inability to capture strong dilution effects (e.g., in Experiments 9 and 13), a `cue_cost` parameter has been introduced. This represents a fixed penalty subtracted from the accumulator for each active cue evaluated. While highly valid early cues will have weights that exceed this cost (yielding a net positive value), the exponential decay guarantees that subsequent weak cues will eventually have weights lower than the cost. When this happens, evaluating those weak cues actively degrades the option's accumulated score, elegantly producing the strong dilution effects observed in the data without leaving the Sequential Search family.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate model successfully implemented the arbiter's prescribed 'Sequential Search with Evidence Accumulation and Decay' mechanism and achieved a new running-best loss (ACCEPTED). However, the model still struggles significantly with experiments that show strong dilution effects (e.g., Experiment 9 and Experiment 13) and Experiment 22. In Experiment 9, the observed metric is strongly negative (-0.7263), indicating that adding weak cues to an option makes it *less* likely to be chosen (classic dilution). The candidate yields a positive value (0.2621), meaning the weak cues are still strictly adding value rather than diluting. While the arbiter prescribed this family to explain the *lack* of dilution in some experiments, we still need the flexibility to capture dilution when it occurs.
Rationale: To better capture the dilution-like effects within the prescribed Sequential Search family, adjust the mechanism so that the accumulation can sometimes penalize an option. One way to do this without leaving the family is to allow the `decay` parameter to take on negative values (e.g., range [-1.0, 1.0]), which would allow subsequent weak cues to actively discount the accumulated evidence (mimicking a penalty for low-validity information). Alternatively, introduce a small fixed cost/penalty per cue evaluated, subtracting from the accumulator, so that evaluating many weak cues degrades the option's score. Keep the core sequential search and thresholding intact.

**Outcome of this advice:** iter 1 candidate loss=0.3125 -> iter 2 candidate loss=0.3068 -> the gate marked it ACCEPTED.

### Iteration 2
Verdict: regenerate
Interpretation: The candidate model successfully integrated the `cue_cost` mechanism, which led to a lower aggregate loss and was ACCEPTED by the gate. The addition of `cue_cost` significantly improved the fit on Experiment 13 (moving from 0.2000 to -0.5225, much closer to the real -0.6683) and moved Experiment 9 in the right direction (from 0.2621 to 0.0453). However, Experiment 9 still fails to show the strong negative dilution effect observed in human data (-0.7263). Additionally, the model remains highly inaccurate on Experiment 22 (predicting 0.8442 vs real 0.1768). The current parameter bounds or the exact formulation of the cost might be limiting the model's ability to fully capture these phenomena.
Rationale: The `cue_cost` addition was a success, but it needs to be stronger to fully capture the dilution in Experiment 9 and address the massive miss in Experiment 22. First, widen the range of `cue_cost` to [0.0, 2.0] so it can exceed the validity of even moderately strong cues if needed. Second, consider making the `cue_cost` relative to the maximum validity or the first cue's weight, so that the penalty scales appropriately across different experiment designs. Keep the Sequential Search with Decay and Threshold family intact, as it is moving the loss in the right direction.

**Outcome of this advice:** iter 2 candidate loss=0.3068 -> iter 3 candidate loss=0.3215 -> the gate marked it REJECTED.

### Iteration 3
Verdict: regenerate
Interpretation: The candidate model was REJECTED by the accept gate, as its loss increased from 0.3068 to 0.3215. The attempt to scale `cue_cost` relative to the maximum validity and expand its bounds to 2.0 worsened the overall fit, indicating that a dynamic or overly large penalty disrupts the delicate balance of the sequential search mechanism across experiments. In particular, the massive miss on Experiment 22 remains unresolved, and the model failed to capture the strong negative dilution in Experiment 9 better than the previous iteration.
Rationale: Since scaling `cue_cost` by the maximum validity was rejected by the gate, revert to the absolute `cue_cost` formulation from Iteration 2. To capture the strong dilution effects (Exp 9) and the preference reversals (Exp 22) without breaking the balance, introduce flexibility in the decay mechanism itself rather than relying solely on a massive fixed cost. Specifically, expand the bounds of the `decay` parameter to [-1.0, 1.0]. A negative decay allows the model to actively discount or flip the valence of lower-validity cues (mimicking a severe penalty for relying on weak evidence) while keeping the Sequential Search with Threshold family intact. Keep `cue_cost` in a moderate range like [0.0, 1.0].

**Outcome of this advice:** iter 3 candidate loss=0.3215 -> iter 4 candidate loss=0.3149 -> the gate marked it REJECTED.

### Iteration 4
Verdict: regenerate
Interpretation: The candidate model (Iteration 4) was REJECTED by the accept gate, meaning the expansion of the `decay` parameter bounds to negative values worsened the aggregate loss compared to the Iteration 2 base. The core issue with the Iteration 2 base on experiments like Exp 9 (strong dilution) and Exp 22 (preference reversals) is that the Sequential Search mechanism often stops too early. If the threshold is small, a strong first cue immediately triggers a decision, preventing the model from ever evaluating the subsequent weak cues. Because the weak cues are never evaluated, their `cue_cost` penalties are never applied, and the model fails to predict the strong negative dilution effects observed in human data.
Rationale: Since negative decay was rejected, we will build on the Iteration 2 base (which had absolute `cue_cost` and standard `decay`). To allow the `cue_cost` penalty to actually take effect on weak cues, we must prevent the model from always stopping at the first cue. Do this by raising the minimum bound of the `threshold` parameter (e.g., from [0.0, 5.0] to [1.0, 5.0] or [0.5, 5.0]). Since individual cue validities are strictly less than 1.0, a threshold > 1.0 ensures the model evaluates at least a few cues before early stopping can trigger. This forces the integration of weaker cues, allowing their `cue_cost` penalties to accumulate and drive the strong dilution effects needed for Exp 9 and Exp 22, while keeping the prescribed Sequential Search family fully intact.

**Outcome of this advice:** iter 4 candidate loss=0.3149 -> iter 5 candidate loss=0.3501 -> the gate marked it REJECTED.

### Iteration 5 (most recent — address this)
Verdict: regenerate
Interpretation: The current candidate (Iteration 5) was REJECTED by the accept gate, meaning the aggregate loss worsened compared to the Iteration 2 base. The attempt to force cue integration by raising the minimum `threshold` to 0.5 failed because it broke the model's ability to perform Take-The-Best (TTB) early stopping, which is essential for capturing human behavior in several other experiments. Furthermore, the continued reliance on a `cue_cost` penalty to drive dilution is drifting away from the arbiter's explicit recommendation, which stated that 'weak cues contribute very little to the decision rather than actively penalizing the strong cues.'
Rationale: Since raising the global threshold lower-bound was rejected, we must return to the Iteration 2 base and find a more flexible way to balance TTB and Tallying behaviors without breaking the prescribed family. First, remove the `cue_cost` parameter entirely to strictly align with the arbiter's vision (weak cues should simply decay, not actively penalize). Second, to allow the model to capture tallying in experiments like Exp 22 without ruining TTB in others, modify the early stopping condition. Instead of a fixed absolute threshold, make the stopping condition relative to the remaining available evidence (e.g., stop if `abs(acc_a - acc_b) >= threshold * sum(remaining_validities)`), or introduce a probabilistic stopping rule (e.g., stopping with probability `1 - exp(-diff / threshold)`). This allows the search to naturally continue when the accumulated difference is small compared to what's left, seamlessly bridging TTB and Tallying within the Sequential Search framework.

**Outcome of this advice:** iter 5 candidate loss=0.3501 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL — MINIMAL-DIFF EDIT (do NOT rewrite from scratch)
The RUNNING-BEST (last ACCEPTED) candidate is shown verbatim above under `## PREVIOUS CANDIDATE (this loop)`. This is the base the loop's accept gate is currently keeping; the most recent critic feedback (see `## PRIOR FEEDBACK ITERATIONS`) should be applied on top of it. Apply the SMALLEST edit that addresses the critic's diagnosis while staying inside the arbiter's prescribed mechanism family:
  - Re-emit the previous source verbatim, then change ONLY the lines needed to address the critic (a parameter range, a normalization, a softmax temperature, an attention scheme, a gating term, a buggy indexing line, etc.).
  - Keep all unaffected functions, equations, parameter names, and the overall mechanism intact.
  - Do NOT rewrite `predict` / `policy` end-to-end if a few lines would do, and do NOT switch mechanism families — that is the arbiter's decision, not yours in this loop.
  - Briefly explain the minimal edit in `rationale`.
If you genuinely believe a larger rewrite is required, you may do one, but justify in `rationale` why the minimal-diff path was insufficient.

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
  "theory": "Sequential Search with Relative Evidence Thresholding: Decision-makers evaluate cues in descending order of validity. Each active cue adds to an evidence accumulator, but the subjective weight of each subsequent cue decays exponentially. Instead of a fixed absolute threshold for early stopping, subjects use a relative stopping rule: they stop searching when the accumulated evidence difference between options exceeds a threshold proportional to the maximum possible remaining evidence. This relative threshold seamlessly bridges Take-The-Best (stopping when remaining evidence cannot change the outcome) and Tallying (integrating all cues), explaining dynamic strategy shifts without relying on artificial cue penalties.",
  "predict": "def predict(parameters, stimulus, history):\n    import numpy as np\n    \n    stim = np.asarray(stimulus, dtype=float)\n    val = np.asarray(parameters[\"validities\"], dtype=float)\n    \n    a, b = stim[0], stim[1]\n    \n    decay = float(parameters[\"decay\"])\n    threshold = float(parameters[\"threshold\"])\n    beta = float(parameters[\"beta\"])\n    epsilon = float(parameters[\"epsilon\"])\n    \n    # Sort cues by validity in descending order\n    cue_order = np.argsort(-val, kind=\"stable\").tolist()\n    \n    acc_a = 0.0\n    acc_b = 0.0\n    \n    # Evaluate cues sequentially\n    for k, j in enumerate(cue_order):\n        # Exponential decay of subjective weight based on cue rank\n        weight = val[j] * (decay ** k)\n        \n        # Add weight for each active cue\n        if a[j] == 1:\n            acc_a += weight\n        if b[j] == 1:\n            acc_b += weight\n        \n        # Calculate the maximum possible remaining evidence\n        remaining_evidence = sum(val[cue_order[m]] * (decay ** m) for m in range(k + 1, len(cue_order)))\n        \n        # Early stopping if the evidence difference reaches the relative threshold\n        if abs(acc_a - acc_b) >= threshold * remaining_evidence:\n            break\n            \n    scores = np.array([acc_a, acc_b])\n    z = beta * (scores - np.max(scores))\n    e = np.exp(z)\n    p = e / np.sum(e)\n    \n    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])\n",
  "policy": "def policy(probabilities):\n    import numpy as np\n    probabilities = np.asarray(probabilities, dtype=np.float64)\n    probabilities /= probabilities.sum()\n    return np.random.choice(len(probabilities), p=probabilities)\n",
  "parameters": {
    "decay": "[0.0, 1.0]",
    "threshold": "[0.0, 5.0]",
    "beta": "[0.1, 20.0]",
    "epsilon": "[0.0, 0.5]",
    "validities": "validities"
  },
  "rationale": "Following the critic's feedback, `cue_cost` has been completely removed to align with the arbiter's original vision that weak cues simply decay rather than actively penalizing strong ones. To balance Take-The-Best and Tallying behaviors without breaking the Sequential Search family, the early stopping condition was modified to be relative to the remaining available evidence. The search now stops if the absolute difference in accumulated evidence is greater than or equal to `threshold` times the sum of the remaining decayed validities. When `threshold=1.0`, this perfectly mimics TTB logic (stopping when the remaining cues cannot possibly flip the decision). When `threshold > 1.0`, it forces deeper search (Tallying), and when `< 1.0`, it allows more impulsive decisions. This relative thresholding provides the flexibility needed to capture behavior across different experiments without artificial penalties."
}
```
```

## Usage

```json
{
  "prompt_token_count": 33450,
  "candidates_token_count": 931,
  "total_token_count": 36261
}
```
