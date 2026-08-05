# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_9" and "pi_2") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_9" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_9
Tallying with Salience-Biased Tie-Breaking (Normalized Mixture with Flexible Scaling): Decision-makers evaluate options by integrating two separate signals. The primary signal is a pure Tally (counting the number of winning features for each option). The secondary signal is a non-linear validity-weighted score that can either penalize missing top-validity features or, conversely, over-weight lower-validity features depending on the individual's cognitive strategy. Both signals are normalized to a [0, 1] scale before being linearly mixed by an individual-specific parameter 'alpha'. Allowing the non-linear scaling parameter 'gamma' to take negative values captures the empirical phenomenon where some subjects strongly prefer options that win on lower-validity features when the tally is tied.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")

    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    gamma = float(parameters["gamma"])
    alpha = float(parameters["alpha"])
    
    # Apply non-linear exponential scaling to validities for the tie-breaking component
    w = val ** gamma
    
    # Only count features where one option strictly beats the other
    a_wins = (a > b).astype(float)
    b_wins = (b > a).astype(float)
    
    # Pure Tallying component (normalized)
    n_feat = len(val)
    tally_a = np.sum(a_wins) / n_feat
    tally_b = np.sum(b_wins) / n_feat
    
    # Non-linear validity-weighted component (normalized)
    sum_w = np.sum(w)
    if sum_w == 0:
        sum_w = 1.0
    wadd_a = np.sum(w * a_wins) / sum_w
    wadd_b = np.sum(w * b_wins) / sum_w
    
    # Linear mixture of Normalized Tallying and Salience-Biased WADD
    score_a = alpha * tally_a + (1.0 - alpha) * wadd_a
    score_b = alpha * tally_b + (1.0 - alpha) * wadd_b
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
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


## EXPERIMENT 1 (proposed by pi_9)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 6: A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** To dissociate the Advocated Theory (Tallying with Salience-Biased Tie-Breaking) from Pure Tallying, we exploit trials where the two models diverge in their treatment of validities. Pure Tallying ignores validities entirely, predicting a strict 50/50 guess whenever the total number of winning features is tied, and predicting choices based solely on the count difference otherwise. The Advocated Theory integrates a non-linear validity-weighted component that can either heavily weight high-validity cues or paradoxically weight low-validity cues (via a negative gamma). We include 'tally tie' trials where options win on disjoint sets of features with varying validities (e.g., highest vs. lowest validities); Pure Tallying predicts 50/50, while the Advocated Theory predicts a systematic preference. We also include 'conflict' trials where an option wins the tally but loses on highly salient features, causing the Advocated Theory to attenuate or reverse the pure tallying prediction.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Pure Tallying predicts a strict 50/50 guess on trials where the number of winning features is tied between options, regardless of the validities of those features. Its choice probabilities on these trials are exactly 0.5. In contrast, the Advocated Theory incorporates a validity-weighted tie-breaking component that biases choices systematically away from 0.5 on these trials. By calculating the mean squared deviation of subjects' choice proportions from 0.5 specifically on tally-tie trials, we expect a value close to binomial noise (~0.015) for Pure Tallying, and a significantly larger value for the Advocated Theory.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    # Extract option ratings as numpy arrays
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    # Calculate tallies for each option
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    # Identify trials where the tally is tied
    tie_mask = (a_wins == b_wins)
    tie_data = data[tie_mask].copy()
    
    if len(tie_data) == 0:
        return 0.0
    
    # Create a hashable trial identifier
    tie_data['trial_id'] = tie_data.apply(lambda r: tuple(r['option_a_ratings']) + tuple(r['option_b_ratings']), axis=1)
    
    # Calculate the proportion of times each subject chose Option A (response == 0) for each tally-tie trial type
    p_a = tie_data.groupby(['subject_id', 'trial_id'])['response'].apply(lambda x: (x == 0).mean())
    
    # Calculate the mean squared deviation from 0.5 (random guessing)
    sq_dev = (p_a - 0.5) ** 2
    
    return float(sq_dev.mean())

### RESULTS
- Predicted under pi_9 (simulated): 0.0426 (var=0.0019)
- Predicted under pi_2 (simulated): 0.0140 (var=0.0001)
- Observed on real data: 0.1591 (var=0.0033)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 2: A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 4: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 6: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]

**Rationale:** To strongly dissociate Pure Tallying from the Competing Theory (Tallying with Salience-Biased Tie-Breaking), this design exploits the core difference in how they handle cue validities. Pure Tallying evaluates options strictly by counting the number of winning features, ignoring validities completely; it predicts a 50/50 guess whenever the tally is tied. The Competing Theory integrates a non-linear validity-weighted component that breaks tally ties and modulates preference strength based on validities. We include 'tally tie' trials where options win on disjoint sets of features with varying validities (e.g., highest vs. lowest); Pure Tallying predicts exactly 50/50, while the Competing Theory predicts a systematic preference. We also include 'conflict' trials where one option wins the tally but loses the highest-validity features, causing the Competing Theory to attenuate or reverse the pure tallying prediction.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the mean squared difference in the proportion of 'A' choices between Trial 4 (where A wins the top 3 validities) and Trial 3 (where A wins the bottom 3 validities). Under Pure Tallying, A wins 3-2 in both trials, so the underlying choice probability is identical and the squared difference merely reflects binomial response noise. Under the Competing Theory, the validity-weighted component strongly differentiates these two trials, leading to a systematically larger squared difference.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t3_mask = data['a_str'] == '00111'
    t4_mask = data['a_str'] == '11100'
    
    t3_data = data[t3_mask]
    t4_data = data[t4_mask]
    
    if len(t3_data) == 0 or len(t4_data) == 0:
        return 0.0
        
    p_a_t3 = 1.0 - t3_data.groupby('subject_id')['response'].mean()
    p_a_t4 = 1.0 - t4_data.groupby('subject_id')['response'].mean()
    
    df = pd.DataFrame({'t3': p_a_t3, 't4': p_a_t4}).dropna()
    if len(df) == 0:
        return 0.0
        
    return float(np.mean((df['t4'] - df['t3'])**2))

### RESULTS
- Predicted under pi_9 (simulated): 0.1796 (var=0.0754)
- Predicted under pi_2 (simulated): 0.0132 (var=0.0004)
- Observed on real data: 0.4773 (var=0.0539)

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
**Predicted under pi_9:** 0.1933 (var=0.0120)
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
**Predicted under pi_9:** 0.7689 (var=0.0229)
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
**Predicted under pi_9:** 0.3733 (var=0.0806)
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
**Predicted under pi_9:** 0.2450 (var=0.3518)
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
**Predicted under pi_9:** 0.5325 (var=0.0115)
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
**Predicted under pi_9:** 0.5042 (var=0.0188)
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
**Predicted under pi_9:** 0.3075 (var=0.0064)
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
**Predicted under pi_9:** 0.7608 (var=0.0199)
**Predicted under pi_2:** 0.8458 (var=0.0099)

### Experiment 11
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
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
```

**Observed (real) value:** 0.1163 (var=0.0129)
**Predicted under pi_9:** 0.3619 (var=0.0638)
**Predicted under pi_2:** 0.1650 (var=0.0156)

### Experiment 12
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
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
```

**Observed (real) value:** 0.1495 (var=0.0219)
**Predicted under pi_9:** 0.3726 (var=0.0891)
**Predicted under pi_2:** 0.1589 (var=0.0143)

### Experiment 13
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    tally_A_ttb_A_choices = []
    tally_A_ttb_B_choices = []
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        ttb_winner = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_winner = 'A'
                break
            elif b[i] > a[i]:
                ttb_winner = 'B'
                break
                
        if a_wins == 3 and b_wins == 2:
            is_A = 1 if row['response'] == 0 else 0
            if ttb_winner == 'A':
                tally_A_ttb_A_choices.append(is_A)
            elif ttb_winner == 'B':
                tally_A_ttb_B_choices.append(is_A)
                
    mean_A_ttb_A = np.mean(tally_A_ttb_A_choices) if len(tally_A_ttb_A_choices) > 0 else 0.5
    mean_A_ttb_B = np.mean(tally_A_ttb_B_choices) if len(tally_A_ttb_B_choices) > 0 else 0.5
    
    return float(mean_A_ttb_A - mean_A_ttb_B)
```

**Observed (real) value:** 0.8075 (var=0.0287)
**Predicted under pi_9:** 0.0550 (var=0.0253)
**Predicted under pi_2:** -0.0325 (var=0.0103)

### Experiment 14
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    # Calculate tally scores
    a_wins = np.sum(a > b, axis=1)
    b_wins = np.sum(b > a, axis=1)
    
    # Identify tally tie trials
    ties = (a_wins == b_wins)
    if not np.any(ties):
        return 0.5
        
    # For tie trials, determine the TTB prediction
    # Feature 0 has the highest validity in this design
    a_f0 = a[ties, 0]
    b_f0 = b[ties, 0]
    
    responses = data['response'].values[ties]
    
    ttb_choices = np.where(a_f0 > b_f0, 0, np.where(b_f0 > a_f0, 1, -1))
    
    valid = ttb_choices != -1
    if not np.any(valid):
        return 0.5
        
    return float(np.mean(responses[valid] == ttb_choices[valid]))
```

**Observed (real) value:** 0.5208 (var=0.0051)
**Predicted under pi_9:** 0.5079 (var=0.0188)
**Predicted under pi_2:** 0.4975 (var=0.0054)

### Experiment 15
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    target_A = (1, 1, 1, 0, 0, 0)
    target_B = (0, 0, 0, 1, 1, 1)
    
    a_match = data['option_a_ratings'].apply(lambda x: tuple(x) == target_A)
    b_match = data['option_b_ratings'].apply(lambda x: tuple(x) == target_B)
    idx1 = a_match & b_match
    
    a_match_rev = data['option_a_ratings'].apply(lambda x: tuple(x) == target_B)
    b_match_rev = data['option_b_ratings'].apply(lambda x: tuple(x) == target_A)
    idx2 = a_match_rev & b_match_rev
    
    chose_target = 0
    total = 0
    
    if idx1.any():
        chose_target += (data.loc[idx1, 'response'] == 0).sum()
        total += idx1.sum()
        
    if idx2.any():
        chose_target += (data.loc[idx2, 'response'] == 1).sum()
        total += idx2.sum()
        
    if total == 0:
        return 0.5
        
    return float(chose_target / total)
```

**Observed (real) value:** 0.1832 (var=0.0124)
**Predicted under pi_9:** 0.4747 (var=0.0853)
**Predicted under pi_2:** 0.5116 (var=0.0090)

### Experiment 16
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    t1_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 1, 0, 0, 0)) & data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 0, 1, 1, 1))
    t5_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 0, 1, 1, 1)) & data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 1, 0, 0, 0))
    
    chose_first_half_winner_t1 = (data[t1_mask]['response'] == 0).sum()
    chose_first_half_winner_t5 = (data[t5_mask]['response'] == 1).sum()
    
    total_relevant_trials = t1_mask.sum() + t5_mask.sum()
    if total_relevant_trials == 0:
        return 0.5
        
    return float((chose_first_half_winner_t1 + chose_first_half_winner_t5) / total_relevant_trials)
```

**Observed (real) value:** 0.1762 (var=0.0166)
**Predicted under pi_9:** 0.5006 (var=0.0642)
**Predicted under pi_2:** 0.5069 (var=0.0095)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, Pure Tallying (Theory 2) fails to capture the systematic variance on tie-breaking trials (Exp 1 and 2), where subjects clearly rely on cue validities. However, Theory 1 (Tallying with Salience-Biased Tie-Breaking) also fails on several key experiments (e.g., Exp 13, 15, 16). In Experiment 10, the observed metric is exactly ~0.5, meaning that when Tallying and Take-The-Best (TTB) are in strict conflict, choices are split evenly. This strongly implies a population-level mixture of distinct heuristic strategies (e.g., some subjects use Pure Tallying, others use TTB) rather than a single unified integration mechanism with a negative gamma.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Heuristic Mixture' theory. Instead of integrating tallying and weighted-additive scores within a single evaluation phase, postulate that decision-makers are heterogeneous: a proportion of the population uses Pure Tallying (ignoring validities), while the rest uses Take-The-Best (relying entirely on the single most valid discriminating cue). The model should introduce a parameter 'p_ttb' representing the probability of using the TTB heuristic versus Tallying. Response noise (softmax or lapse) should be applied to the chosen heuristic's output."
}
```

## Usage

```json
{
  "prompt_token_count": 13188,
  "candidates_token_count": 322,
  "total_token_count": 14876
}
```
