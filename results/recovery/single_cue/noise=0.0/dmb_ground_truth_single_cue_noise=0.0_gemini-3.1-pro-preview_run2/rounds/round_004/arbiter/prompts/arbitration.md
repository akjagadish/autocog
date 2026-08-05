# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_6" and "pi_2") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_6" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_6
Normalized Weighted Additive (WADD) Model: Decision-makers evaluate options by computing a weighted sum of their features. To maintain a consistent scale for choice stochasticity across different environments, the subjective weights are normalized to sum to 1. This compensatory mechanism allows multiple lower-validity cues to correctly outweigh a single high-validity cue. The final choice is made via a softmax function over the normalized expected values, mixed with a uniform lapse rate to account for random errors.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")

    val = np.asarray(parameters["validities"], dtype=float)
    # Normalize validities to sum to 1 to bound scores between 0 and 1
    weights = val / np.sum(val)
    
    a, b = stim[0], stim[1]
    
    # Compute weighted sum of features for each option using normalized validities
    score_a = np.sum(a * weights)
    score_b = np.sum(b * weights)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_2
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


## EXPERIMENT 1 (proposed by pi_6)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 6: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate the Weighted Additive (WADD) Model from the Tallying heuristic, we use a 5-feature design with a steep validity distribution (two highly valid experts, three low-validity experts). Tallying simply counts the number of winning features for each option, ignoring their validities. WADD integrates features by weighting them according to their normalized validities. The design includes 'conflict' trials where an option is favored by WADD due to winning the high-validity features, while the alternative is favored by Tallying because it wins on a greater number of low-validity features. We also include 'tally tie' trials where both options win on an equal number of features (leading Tallying to predict a 50/50 guess), but WADD makes a deterministic prediction based on the validity weights.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
The metric computes the proportion of choices consistent with the WADD model on the core 'conflict' trials (Trials 1 and 2). In these trials, one option has two highly valid features but loses on the other three lower-validity features. The WADD model predicts a preference for the option with the two highly valid features because their combined validity outweighs the other three. In contrast, the Tallying heuristic ignores validities and simply counts winning features, thereby strongly preferring the option with three winning features. Measuring the rate of WADD-consistent choices on these specific trials yields a large, reliable gap between the two models.

Source:
def metric(data: pd.DataFrame) -> float:
    wadd_choices = 0
    conflict_trials = 0
    for a, b, resp in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        a_tup = tuple(a)
        b_tup = tuple(b)
        if a_tup == (1, 1, 0, 0, 0) and b_tup == (0, 0, 1, 1, 1):
            conflict_trials += 1
            if resp == 0:
                wadd_choices += 1
        elif a_tup == (0, 0, 1, 1, 1) and b_tup == (1, 1, 0, 0, 0):
            conflict_trials += 1
            if resp == 1:
                wadd_choices += 1
    return wadd_choices / conflict_trials if conflict_trials > 0 else 0.5

### RESULTS
- Predicted under pi_6 (simulated): 0.7206 (var=0.0130)
- Predicted under pi_2 (simulated): 0.1650 (var=0.0156)
- Observed on real data: 0.1163 (var=0.0129)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.5, 0.5, 0.5]

**Trial pairs (n=5):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 4: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Rationale:** This design systematically pits Tallying against the Normalized Weighted Additive (WADD) Model. We use five features with a steep validity distribution (two highly valid cues, three low-validity cues). Tallying evaluates options by counting the number of strictly winning features, completely ignoring their validities. WADD integrates all features by weighting them according to their normalized validities. The design includes 'conflict' trials where WADD prefers the option with fewer, higher-validity features, while Tallying prefers the option with a greater total number of winning features. It also includes 'tally tie' trials where both options win on an equal number of features (leading Tallying to predict a 50/50 guess), but WADD makes a deterministic prediction based on the validity weights. These divergent predictions ensure a strong quantitative dissociation.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
This metric isolates the specific 'conflict' trial where Option A has two highly valid features ([1, 1, 0, 0, 0]) and Option B has three low-validity features ([0, 0, 1, 1, 1]). Tallying ignores validities and simply counts winning features, thereby strictly preferring Option B (3 wins vs 2 wins) and yielding a choice proportion < 0.5 for the target option. In contrast, WADD computes the normalized weighted sum, correctly recognizing that the two valid features outweigh the three invalid ones, thus strictly preferring the target option and yielding a choice proportion > 0.5. The difference in prediction direction ensures strong separability between the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    target_chosen = []
    for _, row in data.iterrows():
        a = tuple(int(x) for x in row['option_a_ratings'])
        b = tuple(int(x) for x in row['option_b_ratings'])
        
        # Identify the strict conflict trial
        is_A_target = (a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1))
        is_B_target = (b == (1, 1, 0, 0, 0) and a == (0, 0, 1, 1, 1))
        
        if is_A_target or is_B_target:
            chose_A = (row['response'] == 0)
            if (is_A_target and chose_A) or (is_B_target and not chose_A):
                target_chosen.append(1)
            else:
                target_chosen.append(0)
                
    if len(target_chosen) == 0:
        return 0.5
    return float(np.mean(target_chosen))

### RESULTS
- Predicted under pi_6 (simulated): 0.7200 (var=0.0169)
- Predicted under pi_2 (simulated): 0.1589 (var=0.0143)
- Observed on real data: 0.1495 (var=0.0219)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
import pandas as pd
import numpy as np

def metric(data: pd.DataFrame) -> float:
    ttb_aligned = 0
    total = len(data)
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_pred = None
        # The features are already ordered by validity in the design (0 is highest)
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
                
        if ttb_pred == resp:
            ttb_aligned += 1
            
    return float(ttb_aligned / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.2467 (var=0.0072)
**Predicted under pi_6:** 0.1665 (var=0.0100)
**Predicted under pi_2:** 0.1503 (var=0.0075)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    mask = a_wins != b_wins
    if not np.any(mask):
        return 0.5
        
    tally_choices = np.where(a_wins > b_wins, 0, 1)
    matches = (data['response'].values[mask] == tally_choices[mask])
    
    return float(np.mean(matches))
```

**Observed (real) value:** 0.8444 (var=0.0148)
**Predicted under pi_6:** 0.8183 (var=0.0129)
**Predicted under pi_2:** 0.8617 (var=0.0104)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify critical trials where WADD and Tallying make strictly opposite predictions.
    # Trial 1: A has fewer but higher-validity features, B has more but lower-validity features.
    # WADD prefers A, Tallying prefers B.
    is_t1 = (data['option_a_ratings'].apply(tuple) == (1, 1, 0, 0, 0)) & (data['option_b_ratings'].apply(tuple) == (0, 0, 1, 1, 1))
    
    # Trial 5: The reversed version of Trial 1.
    # WADD prefers B, Tallying prefers A.
    is_t5 = (data['option_a_ratings'].apply(tuple) == (0, 0, 1, 1, 1)) & (data['option_b_ratings'].apply(tuple) == (1, 1, 0, 0, 0))
    
    # Count choices that align with the WADD model's predictions
    wadd_aligned_t1 = (data.loc[is_t1, 'response'] == 0).sum()
    wadd_aligned_t5 = (data.loc[is_t5, 'response'] == 1).sum()
    
    total_critical = is_t1.sum() + is_t5.sum()
    
    if total_critical == 0:
        return 0.5
        
    return float((wadd_aligned_t1 + wadd_aligned_t5) / total_critical)
```

**Observed (real) value:** 0.1317 (var=0.0093)
**Predicted under pi_6:** 0.5517 (var=0.0100)
**Predicted under pi_2:** 0.1833 (var=0.0123)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trial 1: A=[1, 1, 0, 0, 0], B=[0, 0, 1, 1, 1]
    is_trial_1 = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0)) & \
                 data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
    
    # Identify trial 6: A=[0, 0, 1, 1, 1], B=[1, 1, 0, 0, 0]
    is_trial_6 = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1)) & \
                 data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))
    
    # Calculate the proportion of choosing option B on these trials
    p_b_trial_1 = data.loc[is_trial_1, 'response'].mean()
    p_b_trial_6 = data.loc[is_trial_6, 'response'].mean()
    
    # Handle cases where a subject might not have these trials (though with 12 reps it's very unlikely)
    if pd.isna(p_b_trial_1) or pd.isna(p_b_trial_6):
        return 0.0
        
    # Return the difference in preference for B between Trial 1 and Trial 6
    return float(p_b_trial_1 - p_b_trial_6)

```

**Observed (real) value:** 0.6933 (var=0.0487)
**Predicted under pi_6:** -0.5183 (var=0.0715)
**Predicted under pi_2:** 0.7350 (var=0.0538)

### Experiment 7
**Design**
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    top_cue_chosen = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        # Focus on trials where the tally is tied and the top cue (index 0) breaks the tie
        if a_wins == b_wins and a[0] != b[0]:
            if a[0] > b[0]:
                top_cue_chosen.append(1 if row['response'] == 0 else 0)
            else:
                top_cue_chosen.append(1 if row['response'] == 1 else 0)
                
    if len(top_cue_chosen) == 0:
        return 0.5
    return float(np.mean(top_cue_chosen))
```

**Observed (real) value:** 0.4850 (var=0.0026)
**Predicted under pi_6:** 0.6212 (var=0.0054)
**Predicted under pi_2:** 0.5117 (var=0.0065)

### Experiment 8
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    a_wins = (a_ratings > b_ratings).sum(axis=1)
    b_wins = (b_ratings > a_ratings).sum(axis=1)
    
    a_top = a_ratings[:, 0] > b_ratings[:, 0]
    b_top = b_ratings[:, 0] > a_ratings[:, 0]
    
    is_tie = (a_wins == b_wins)
    
    target_trials = is_tie & (a_top | b_top)
    
    if not np.any(target_trials):
        return 0.5
        
    responses = data['response'].values[target_trials]
    a_top_target = a_top[target_trials]
    b_top_target = b_top[target_trials]
    
    match = ( (responses == 0) & a_top_target ) | ( (responses == 1) & b_top_target )
    
    return float(np.mean(match))
```

**Observed (real) value:** 0.5283 (var=0.0043)
**Predicted under pi_6:** 0.7400 (var=0.0208)
**Predicted under pi_2:** 0.5117 (var=0.0105)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

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
        for i in range(5):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        if ttb_pred is not None:
            matches.append(1 if resp == ttb_pred else 0)
    if not matches:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.3475 (var=0.0033)
**Predicted under pi_6:** 0.3167 (var=0.0054)
**Predicted under pi_2:** 0.2592 (var=0.0055)

### Experiment 10
**Design**
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Extract ratings into 2D numpy arrays
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    # Tallying predictions: count features where one option strictly beats the other
    tally_a = np.sum(a_ratings > b_ratings, axis=1)
    tally_b = np.sum(b_ratings > a_ratings, axis=1)
    tally_c = np.where(tally_a > tally_b, 0, np.where(tally_b > tally_a, 1, -1))
    
    # Take-The-Best predictions: purely determined by the highest-validity feature (index 0)
    ttb_c = np.where(a_ratings[:, 0] > b_ratings[:, 0], 0, 1)
    
    # Isolate trials where the two heuristics make deterministic, opposite predictions
    mask = (tally_c != -1) & (tally_c != ttb_c)
    
    if not np.any(mask):
        return 0.5
        
    # Calculate the proportion of choices that align with the Tallying heuristic
    responses = data['response'].values[mask]
    tally_choices = tally_c[mask]
    
    return float(np.mean(responses == tally_choices))
```

**Observed (real) value:** 0.4975 (var=0.0028)
**Predicted under pi_6:** 0.8508 (var=0.0110)
**Predicted under pi_2:** 0.8458 (var=0.0099)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the majority of experiments, Tallying (THEORY 2) substantially outperforms the Normalized Weighted Additive model (THEORY 1). WADD dramatically mispredicts outcomes in Experiments 1, 2, 5, 6, and 8, whereas Tallying provides predictions much closer to the observed data. However, Experiment 10 isolates trials where Tallying and Take-The-Best (TTB) make opposite predictions, and the observed alignment with Tallying is ~0.50 (chance), whereas both Tallying and WADD predict ~0.85. This suggests that neither Tallying nor WADD completely captures the population behavior on these trials, and a significant portion of subjects might be using a lexicographic strategy like TTB. THEORY 1 (WADD) is fundamentally failing to capture the robust heuristic-like behavior seen across the experiments and should be replaced with a stronger classical competitor.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace the WADD theory with the Take-The-Best (TTB) heuristic. The TTB theory should posit that decision-makers process cues lexicographically: they search through features in descending order of their validities, stop at the first feature that discriminates between the two options (one option has a 1, the other a 0), and choose the option favored by that cue. If no cues discriminate, they guess randomly. This introduces a non-compensatory heuristic that strongly contrasts with Tallying (which integrates all cues equally) and can help explain the ~0.50 observed in Experiment 10 if we assume a mixture of TTB and Tallying strategies in the population."
}
```

## Usage

```json
{
  "prompt_token_count": 8964,
  "candidates_token_count": 376,
  "total_token_count": 10479
}
```
