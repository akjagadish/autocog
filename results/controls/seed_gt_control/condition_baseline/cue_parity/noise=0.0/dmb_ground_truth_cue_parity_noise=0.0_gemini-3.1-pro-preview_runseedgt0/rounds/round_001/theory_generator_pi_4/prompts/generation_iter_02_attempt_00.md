# generation_iter_02_attempt_00

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
- THEORY 1 = `pi_1`
- THEORY 2 = `pi_3`
- The recommendation below acts on THEORY 2 (= `pi_3`).

Theory 1 (Cue-Parity) is exceptionally well-supported by the data, indicating that subjects compute parity across all available cues rather than truncating to a subset of high-validity cues. Since Lexicographic Parity (Theory 2) fails, propose a brand-new theory that acts as a strong competitor to Cue-Parity. A potential direction is to explore whether the parity computation is modulated by cue validities (e.g., a 'Weighted Parity' model where features contribute to the parity count probabilistically based on their validity) or if there is an interaction between Tallying (simple majority) and Parity on trials where the two conflict. The new theory should preserve the non-monotone, parity-like nature of the decision rule but introduce a novel psychological mechanism for how the features are integrated.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_1` (overall score: 0.985)

**Description**
People decide by the PARITY of the evidence rather than its weight or direction. They count the number of cues on which option A strictly beats option B, and prefer A when that count is ODD and B when it is EVEN (zero counts as even). This is a deliberately non-monotone, XOR-like rule: adding one more cue in A's favor flips the preference rather than strengthening it, so option dominance does NOT imply choice — an option that wins on every cue (an even count, when the cue number is even) is rejected. The rule uses no validities and no magnitudes, only the parity of feature-wise wins, which makes it an adversarially hard recovery target: it is uncorrelated with any single cue and with the validity-weighted sum, yet perfectly deterministic, much like the anti-majority ensemble. Response noise enters through a softmax over the binary score (winner = 1, loser = 0) with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Cue-Parity: prefer A iff the number of cues where A strictly beats B is
    # ODD, else prefer B (zero A-wins is even -> B). Non-monotone in the
    # evidence; uses neither validities nor magnitudes. Stimulus is the pair
    # of option feature vectors: (2, n_features), row 0 = A, row 1 = B.
    # History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Cue-Parity expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    a_wins = int(np.sum(a > b))
    # Odd number of A-favoring cues -> A (0); even (including zero) -> B (1).
    winner = 0 if (a_wins % 2 == 1) else 1

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the binary
    # score this collapses to sigmoid(beta) for the winner (beta=0 ↔ 50/50;
    # beta ≫ 1 ↔ deterministic).
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
- Experiment 1: real=0.7539 (var=0.0403) vs this=0.7083 (var=0.0555)
- Experiment 2: real=0.8178 (var=0.0117) vs this=0.8596 (var=0.0092)
- Experiment 3: real=0.8358 (var=0.0105) vs this=0.8479 (var=0.0101)
- Experiment 4: real=0.1367 (var=0.0064) vs this=0.1700 (var=0.0169)


---

### `pi_3` (overall score: 0.407)

**Description**
Lexicographic Parity (Tightened)

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Lexicographic Parity expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    
    validities = np.asarray(parameters["validities"], dtype=float)
    n_features = len(validities)
    
    # Determine the number of top cues to consider based on k_frac
    k_frac = float(parameters["k_frac"])
    k = int(np.round(k_frac * n_features))
    if k < 1:
        k = 1
        
    # Get indices of the top k validities (stable sort to preserve original order on ties)
    top_k_idx = np.argsort(validities, kind='mergesort')[-k:]
    
    a_top = a[top_k_idx]
    b_top = b[top_k_idx]
    
    # Count strict A wins within the top K valid cues
    a_wins = int(np.sum(a_top > b_top))
    
    # Odd number of A-wins -> A (0); even -> B (1)
    winner = 0 if (a_wins % 2 == 1) else 1
    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax conversion with numerical stability
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
- validities: validities
- k_frac: [0.5, 1.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.7539 (var=0.0403) vs this=0.5431 (var=0.0498)
- Experiment 2: real=0.8178 (var=0.0117) vs this=0.8516 (var=0.0121)
- Experiment 3: real=0.8358 (var=0.0105) vs this=0.4615 (var=0.0550)
- Experiment 4: real=0.1367 (var=0.0064) vs this=0.3667 (var=0.0840)


---

### `pi_2` (overall score: 0.000)

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
- Experiment 1: real=0.7539 (var=0.0403) vs this=-0.7050 (var=0.0284)
- Experiment 2: real=0.8178 (var=0.0117) vs this=0.5018 (var=0.0052)
- Experiment 3: real=0.8358 (var=0.0105) vs this=0.5721 (var=0.0037)
- Experiment 4: real=0.1367 (var=0.0064) vs this=0.5987 (var=0.0025)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.5465 -> ACCEPTED
- iter 2: loss=0.7819 -> REJECTED
Running-best (last ACCEPTED) base: iter 1 at loss=0.5465 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 1, 0, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_wins = data.apply(lambda row: sum(a > b for a, b in zip(row['option_a_ratings'], row['option_b_ratings'])), axis=1)
    b_wins = data.apply(lambda row: sum(b > a for a, b in zip(row['option_a_ratings'], row['option_b_ratings'])), axis=1)
    
    mask_123 = (a_wins.isin([2, 4])) & (b_wins.isin([0, 1]))
    mask_45 = (a_wins == 1) & (b_wins.isin([2, 3]))
    
    val_123 = data.loc[mask_123, 'response'].mean() if mask_123.any() else 0.5
    val_45 = data.loc[mask_45, 'response'].mean() if mask_45.any() else 0.5
    
    return float(val_123 - val_45)
```

**Observed (real) value:** 0.7539 (var=0.0403)
**Previous candidate values (this loop):**
  - iter 1: -0.5394 (var=0.2241) (Δ vs real -1.2933)
  - iter 2 (most recent): 0.1289 (var=0.0394) (Δ vs real -0.6250)
**Other theories' values on this metric (for reference):**
- pi_1: 0.7083 (var=0.0555)
- pi_2: -0.7050 (var=0.0284)
- pi_3: 0.5431 (var=0.0498)

### Experiment 2
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_wins = data.apply(lambda row: sum(1 for x, y in zip(row['option_a_ratings'], row['option_b_ratings']) if x > y), axis=1)
    b_wins = data.apply(lambda row: sum(1 for x, y in zip(row['option_a_ratings'], row['option_b_ratings']) if y > x), axis=1)
    
    mask = a_wins == b_wins
    if not mask.any():
        return 0.5
        
    tied_data = data[mask]
    tied_a_wins = a_wins[mask]
    
    # Cue-Parity predicts A (0) if a_wins is odd, B (1) if a_wins is even
    cp_preds = (tied_a_wins % 2 == 0).astype(int)
    
    matches = (tied_data['response'] == cp_preds).astype(float)
    return float(matches.mean())
```

**Observed (real) value:** 0.8178 (var=0.0117)
**Previous candidate values (this loop):**
  - iter 1: 0.8720 (var=0.0063) (Δ vs real +0.0542)
  - iter 2 (most recent): 0.5102 (var=0.0204) (Δ vs real -0.3076)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5018 (var=0.0052)
- pi_1: 0.8596 (var=0.0092)
- pi_3: 0.8516 (var=0.0121)

### Experiment 3
**Design**
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[1, 1, 1, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 1]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Extract options as 2D arrays
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    # Compute strict A-wins across all 5 cues
    a_wins = np.sum(a_mat > b_mat, axis=1)
    
    # Cue-Parity rule: Odd A-wins -> A (0), Even A-wins -> B (1)
    cp_preds = (a_wins % 2 == 0).astype(int)
    
    # Compute agreement between subjects' responses and Cue-Parity predictions
    responses = data['response'].values
    return float(np.mean(responses == cp_preds))
```

**Observed (real) value:** 0.8358 (var=0.0105)
**Previous candidate values (this loop):**
  - iter 1: 0.6075 (var=0.0040) (Δ vs real -0.2283)
  - iter 2 (most recent): 0.4954 (var=0.0142) (Δ vs real -0.3404)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8479 (var=0.0101)
- pi_3: 0.4615 (var=0.0550)
- pi_2: 0.5721 (var=0.0037)

### Experiment 4
**Design**
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        top3_awins = np.sum(a[:3] > b[:3])
        all_awins = np.sum(a > b)
        
        if (top3_awins % 2) != (all_awins % 2):
            pred = 0 if top3_awins % 2 == 1 else 1
            matches.append(1.0 if row['response'] == pred else 0.0)
            
    if len(matches) == 0:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.1367 (var=0.0064)
**Previous candidate values (this loop):**
  - iter 1: 0.3963 (var=0.0065) (Δ vs real +0.2597)
  - iter 2 (most recent): 0.5797 (var=0.0190) (Δ vs real +0.4430)
**Other theories' values on this metric (for reference):**
- pi_3: 0.3667 (var=0.0840)
- pi_1: 0.1700 (var=0.0169)
- pi_2: 0.5987 (var=0.0025)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Tally-Biased Parity: Decision makers compute both the parity of the evidence (whether the number of cues favoring an option is odd) and a simple tally of wins for each option. The final choice is driven by a weighted combination of the Parity score and the Tallying difference. On trials where tallying yields a tie, the model naturally defaults to pure Cue-Parity, explaining why subjects exhibit strong parity-like behavior specifically on tied trials, while allowing tallying to pull choices on other trials.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Tally-Biased Parity expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    
    a_wins = int(np.sum(a > b))
    b_wins = int(np.sum(b > a))
    
    # Pure Parity score: 1 if odd, 0 if even
    parity_a = 1.0 if (a_wins % 2 == 1) else 0.0
    parity_b = 1.0 - parity_a
    
    w_tally = float(parameters["w_tally"])
    
    # Tally difference
    tally_diff = float(a_wins - b_wins)
    
    # Combine Parity and Tallying
    score_a = parity_a + w_tally * tally_diff
    score_b = parity_b - w_tally * tally_diff
    
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax conversion with numerical stability
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
- w_tally: [0.0, 2.0]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]

`rationale`: Following the arbiter's suggestion to explore an interaction between Parity and Tallying, this theory posits that individuals integrate both signals. The model computes a base Parity score and adjusts it linearly by the difference in the number of features won by each option (Tallying). This elegantly accounts for the results in Experiment 2: when `a_wins == b_wins`, the tally difference is exactly zero and the model reduces to pure Cue-Parity. On other trials where the heuristics conflict, the `w_tally` parameter allows the model to capture the tension between the non-monotone parity rule and the monotone majority rule.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The Tally-Biased Parity model completely misses the empirical pattern in Experiment 1, producing a metric value of -0.5394 compared to the observed 0.7539. In Experiment 1, trials were designed to pit simple Tallying against Cue-Parity (e.g., A has 2 wins, B has 0 wins -> Tally favors A, but Parity is even so it favors B). The observed data strongly align with Parity (choosing B), but the candidate's linear combination allows the Tallying difference to overpower the Parity score, leading to the opposite choice. The model also underperforms on Experiments 3 and 4 compared to pure Cue-Parity.
Rationale: The inclusion of a strong Tallying component actively hurts the model's ability to fit the data, as it pushes predictions in the opposite direction of human behavior when Tally and Parity conflict. Instead of combining Parity with Tallying, please pursue the arbiter's other suggestion: a 'Weighted Parity' model. In this model, the parity computation itself is modulated by cue validities (e.g., higher validity cues have a stronger or more reliable contribution to the parity count, perhaps through probabilistic inclusion or weighted sums before the parity step). This keeps the core mechanism firmly within the Parity family without being overridden by a simple majority tally.

**Outcome of this advice:** iter 1 candidate loss=0.5465 -> iter 2 candidate loss=0.7819 -> the gate marked it REJECTED.

### Iteration 2 (most recent — address this)
Verdict: regenerate
Interpretation: The probabilistic Weighted Parity model (iter 2) performed significantly worse than the previous iteration, dropping performance across almost all experiments (e.g., Exp 2 dropped from 0.872 to 0.510, Exp 3 from 0.607 to 0.495). The root cause is that probabilistic inclusion of cues causes the parity signal (p_odd) to exponentially decay toward 0.5 as the number of cues increases, effectively reducing the model to random guessing. This washes out the core non-monotone parity mechanism that is required to fit the data.
Rationale: The previous recommendation of probabilistic inclusion was rejected by the gate because it destroys the parity signal for multi-cue stimuli. To keep the arbiter's prescribed 'Weighted Parity' family without the exponential decay to 0.5, switch to a deterministic Continuous Weighted Parity. First, compute a weighted sum of A-wins: `weighted_wins = sum(weight_i * I(a_i > b_i))`, where `weight_i = 1.0 + w_validity * (validities[i] - mean(validities))` (or similar). Then, apply a continuous parity function to this sum, such as `parity_score = -np.cos(np.pi * weighted_wins)`. This maps even sums to -1 (favoring B) and odd sums to +1 (favoring A), preserving a robust non-monotone signal while allowing validities to smoothly shift the phase, avoiding the collapse to random guessing.

**Outcome of this advice:** iter 2 candidate loss=0.7819 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "Continuous Weighted Parity: Decision makers compute a parity-like signal, but the contribution of each cue is weighted by its validity. Instead of a discrete odd/even check, the evidence is integrated into a continuous sum of validity-weighted wins, which is then passed through a periodic parity function (e.g., negative cosine). This preserves the core non-monotone XOR-like rule while allowing cue validities to smoothly phase-shift the parity signal, avoiding the catastrophic decay to random guessing seen in probabilistic inclusion models.",
  "predict": "def predict(parameters, stimulus, history):\n    import numpy as np\n    \n    stim = np.asarray(stimulus, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\"Continuous Weighted Parity expects a (2, n_features) stimulus.\")\n    \n    a, b = stim[0], stim[1]\n    \n    validities = np.asarray(parameters[\"validities\"], dtype=float)\n    w_validity = float(parameters[\"w_validity\"])\n    \n    # Calculate weights for each cue based on validity\n    mean_val = np.mean(validities)\n    weights = 1.0 + w_validity * (validities - mean_val)\n    \n    # Compute weighted sum of strict A wins\n    a_wins_mask = (a > b).astype(float)\n    weighted_wins = np.sum(weights * a_wins_mask)\n    \n    # Continuous parity score: maps even integers to -1 (favoring B) and odd integers to +1 (favoring A)\n    parity_score = -np.cos(np.pi * weighted_wins)\n    \n    # Scores for A and B\n    score_a = parity_score\n    score_b = -parity_score\n    \n    scores = np.array([score_a, score_b])\n    \n    beta = float(parameters[\"beta\"])\n    epsilon = float(parameters[\"epsilon\"])\n    \n    # Softmax conversion with numerical stability\n    z = beta * (scores - scores.max())\n    e = np.exp(z)\n    p_core = e / e.sum()\n    \n    n_opts = p_core.shape[0]\n    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)\n",
  "policy": "def policy(probabilities):\n    import numpy as np\n    probabilities = np.asarray(probabilities, dtype=np.float64)\n    probabilities /= probabilities.sum()\n    return int(np.random.choice(len(probabilities), p=probabilities))\n",
  "parameters": {
    "validities": "validities",
    "w_validity": "[0.0, 5.0]",
    "beta": "[0.1, 20.0]",
    "epsilon": "[0.0, 0.5]"
  },
  "rationale": "Following the critic's diagnosis, the previous probabilistic inclusion model failed because the parity signal exponentially decayed to 0.5 for multi-cue stimuli. To preserve the 'Weighted Parity' family without losing the non-monotone signal, this model implements a deterministic Continuous Weighted Parity. Cues contribute to a weighted sum of A-wins based on their validity relative to the mean. A continuous periodic function (negative cosine) maps this sum to a parity score, seamlessly interpolating between odd (+1, favoring A) and even (-1, favoring B). This avoids the collapse to random guessing while allowing validities to modulate the parity computation."
}
```
```

## Usage

```json
{
  "prompt_token_count": 10427,
  "candidates_token_count": 859,
  "total_token_count": 12395
}
```
