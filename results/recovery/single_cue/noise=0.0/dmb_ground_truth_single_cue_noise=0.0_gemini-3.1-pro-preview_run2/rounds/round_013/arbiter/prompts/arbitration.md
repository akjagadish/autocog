# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_15" and "pi_2") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_15" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_15
Tallying with Probabilistic Least-Valid Cue Dropping: To save cognitive effort while maintaining robust integration of information, decision-makers predominantly evaluate all available features (Pure Tallying). However, on a small fraction of evaluations, they boundedly drop the single least valid feature and tally exclusively on the remaining subset. This probabilistic dropping naturally produces subtle Take-The-Best or WADD-like biases in edge cases by occasionally ignoring the lowest-validity cue that might otherwise balance the tally, without destroying the overall pure-tallying majority.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")

    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    p_drop = float(parameters["p_drop"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Sort features by validity in descending order
    order = np.argsort(-val, kind="stable")
    n_features = len(val)
    
    # State 0: Pure Tallying (drop 0 cues)
    a_wins_0 = 0.0
    b_wins_0 = 0.0
    for idx in order:
        if a[idx] > b[idx]:
            a_wins_0 += 1.0
        elif b[idx] > a[idx]:
            b_wins_0 += 1.0
            
    scores_0 = np.array([a_wins_0, b_wins_0])
    z_0 = beta * (scores_0 - np.max(scores_0))
    e_0 = np.exp(z_0)
    p_0 = e_0 / np.sum(e_0)
    
    # State 1: Drop 1 least-valid cue
    a_wins_1 = 0.0
    b_wins_1 = 0.0
    K = max(1, n_features - 1)
    top_cues = order[:K]
    for idx in top_cues:
        if a[idx] > b[idx]:
            a_wins_1 += 1.0
        elif b[idx] > a[idx]:
            b_wins_1 += 1.0
            
    scores_1 = np.array([a_wins_1, b_wins_1])
    z_1 = beta * (scores_1 - np.max(scores_1))
    e_1 = np.exp(z_1)
    p_1 = e_1 / np.sum(e_1)
    
    # Expected choice probabilities (mixture)
    p_core = (1.0 - p_drop) * p_0 + p_drop * p_1
    
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


## EXPERIMENT 1 (proposed by pi_15)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  trial 3: A=[1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  trial 5: A=[0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 6: A=[0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0]
  trial 7: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 8: A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]

**Rationale:** To quantitatively dissociate the Advocated Theory (Tallying with Probabilistic Least-Valid Cue Dropping) from Pure Tallying, we exploit their differing sensitivity to the single least valid feature in a 5-feature design. Pure Tallying treats all features equally, predicting choices based strictly on the overall tally difference, and predicting a 50/50 guess whenever the tally is tied. The Advocated Theory assumes decision-makers occasionally drop the least valid cue and tally the remainder. We include 'tally tie' trials where the least valid cue favors one option; here, the Advocated Theory predicts a systematic preference for the opposing option (since dropping the least valid cue breaks the tie in its favor), whereas Pure Tallying predicts a strict guess. We also include 'tally win' trials where the least valid cue either supports or opposes the tally winner, leading the Advocated Theory to respectively attenuate or amplify the choice probability compared to Pure Tallying. Control trials where the least valid cue is tied ensure both models make identical baseline predictions.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric computes an unweighted proportion of 'target choices' across 6 specific trial types designed to perfectly balance under Pure Tallying. Under Pure Tallying, T1 and T2 are 2-vs-2 ties (50% chance for either). T3 and T4 are 2-vs-1 wins for A, so P(B|T3) + P(A|T4) = (1 - P_win) + P_win = 1.0. T5 and T6 are 2-vs-1 wins for B, so P(A|T5) + P(B|T6) = (1 - P_win) + P_win = 1.0. Summing the probabilities of these 6 target choices yields exactly 3.0 out of 6, meaning the expected proportion is mathematically locked at exactly 0.5 for EVERY subject, regardless of their individual beta or epsilon parameters. This completely eliminates between-subject variance in the expected value under the competing theory.

Under the Advocated Theory (Probabilistic Least-Valid Cue Dropping), every single one of these 6 target choices systematically increases in probability compared to the Tally baseline: ties in T1/T2 are broken in favor of the target, the winner's advantage is amplified in T4/T6 (increasing the target probability), and the winner's advantage is attenuated to a tie in T3/T5 (increasing the target probability from 1-P_win to 0.5). Thus, the expected value strictly exceeds 0.5, yielding a highly robust contrast with maximal Signal-to-Noise Ratio.

Source:
def metric(data: pd.DataFrame) -> float:
    score = 0
    count = 0
    
    for _, row in data.iterrows():
        a = tuple(int(x) for x in row['option_a_ratings'])
        b = tuple(int(x) for x in row['option_b_ratings'])
        resp = int(row['response'])
        
        # T1: Pure Tally ties (2-2). Drop 5th -> B wins (1-2). Target: B
        if a == (1, 0, 0, 0, 1) and b == (0, 1, 1, 0, 0):
            if resp == 1: score += 1
            count += 1
        # T2: Pure Tally ties (2-2). Drop 5th -> A wins (2-1). Target: A
        elif a == (0, 1, 1, 0, 0) and b == (1, 0, 0, 0, 1):
            if resp == 0: score += 1
            count += 1
        # T3: Pure Tally A wins (2-1). Drop 5th -> Tie (1-1). Target: B (attenuated advantage)
        elif a == (1, 0, 0, 0, 1) and b == (0, 0, 0, 1, 0):
            if resp == 1: score += 1
            count += 1
        # T4: Pure Tally A wins (2-1). Drop 5th -> A wins (2-0). Target: A (amplified advantage)
        elif a == (1, 1, 0, 0, 0) and b == (0, 0, 0, 0, 1):
            if resp == 0: score += 1
            count += 1
        # T5: Pure Tally B wins (2-1). Drop 5th -> Tie (1-1). Target: A (attenuated advantage)
        elif a == (0, 0, 0, 1, 0) and b == (1, 0, 0, 0, 1):
            if resp == 0: score += 1
            count += 1
        # T6: Pure Tally B wins (2-1). Drop 5th -> B wins (2-0). Target: B (amplified advantage)
        elif a == (0, 0, 0, 0, 1) and b == (1, 1, 0, 0, 0):
            if resp == 1: score += 1
            count += 1
            
    if count == 0:
        return 0.5
    return float(score) / count

### RESULTS
- Predicted under pi_15 (simulated): 0.5278 (var=0.0023)
- Predicted under pi_2 (simulated): 0.4967 (var=0.0031)
- Observed on real data: 0.1528 (var=0.0126)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  trial 2: A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  trial 3: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 5: A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 0, 1]
  trial 6: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]

**Rationale:** To quantitatively dissociate the Advocated Theory (Pure Tallying) from the Competing Theory (Tallying with Probabilistic Least-Valid Cue Dropping), we exploit their differing sensitivity to the single least valid feature in a 5-feature design. Pure Tallying treats all features equally, predicting choices based strictly on the overall tally difference, and predicting a 50/50 guess whenever the tally is tied. The Competing Theory assumes decision-makers occasionally drop the least valid cue and tally the remainder. We include 'tally tie' trials where the least valid cue favors one option; here, the Competing Theory predicts a systematic preference for the opposing option (since dropping the least valid cue breaks the tie in its favor), whereas Pure Tallying predicts a strict guess. We also include 'tally win' trials where the least valid cue either supports or opposes the tally winner, leading the Competing Theory to respectively attenuate or amplify the choice probability compared to Pure Tallying. Control trials where the least valid cue is tied ensure both models make identical baseline predictions.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric contrasts the choice probability of Option A between Trial 1 and Trial 2. In both trials, Pure Tallying sees a 2-vs-2 tie across all features and thus predicts a 50% chance of choosing A, yielding a metric value around 0. However, the Competing Theory occasionally drops the least valid cue (Feature 5). In Trial 1, dropping Feature 5 breaks the tie in favor of A, leading to p(A) > 0.5. In Trial 2, dropping Feature 5 breaks the tie in favor of B, leading to p(A) < 0.5. Thus, the Competing Theory predicts a strictly positive metric value, providing a clear and specific dissociation.

Source:
def metric(data: pd.DataFrame) -> float:
    # Convert option_a_ratings to string for easy matching
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A=[1, 1, 0, 0, 0], B=[0, 0, 1, 0, 1]
    t1_mask = data['A_str'] == '11000'
    # Trial 2: A=[0, 1, 0, 0, 1], B=[1, 0, 1, 0, 0]
    t2_mask = data['A_str'] == '01001'
    
    # Calculate probability of choosing A (response == 0)
    p_a_t1 = 1.0 - data.loc[t1_mask, 'response'].mean()
    p_a_t2 = 1.0 - data.loc[t2_mask, 'response'].mean()
    
    # Handle edge cases where a subject might miss a trial type
    if pd.isna(p_a_t1):
        p_a_t1 = 0.5
    if pd.isna(p_a_t2):
        p_a_t2 = 0.5
        
    return p_a_t1 - p_a_t2


### RESULTS
- Predicted under pi_15 (simulated): 0.1537 (var=0.0418)
- Predicted under pi_2 (simulated): 0.0038 (var=0.0316)
- Observed on real data: -0.7100 (var=0.0550)

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
**Predicted under pi_15:** 0.1592 (var=0.0066)
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
**Predicted under pi_15:** 0.8456 (var=0.0069)
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
**Predicted under pi_15:** 0.1617 (var=0.0079)
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
**Predicted under pi_15:** 0.6867 (var=0.0513)
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
**Predicted under pi_15:** 0.4721 (var=0.0055)
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
**Predicted under pi_15:** 0.5092 (var=0.0098)
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
**Predicted under pi_15:** 0.2565 (var=0.0037)
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
**Predicted under pi_15:** 0.8608 (var=0.0086)
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
**Predicted under pi_15:** 0.1881 (var=0.0114)
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
**Predicted under pi_15:** 0.1958 (var=0.0143)
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
**Predicted under pi_15:** -0.0713 (var=0.0156)
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
**Predicted under pi_15:** 0.5058 (var=0.0054)
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
**Predicted under pi_15:** 0.5316 (var=0.0159)
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
**Predicted under pi_15:** 0.5400 (var=0.0093)
**Predicted under pi_2:** 0.5069 (var=0.0095)

### Experiment 17
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
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
```

**Observed (real) value:** 0.1591 (var=0.0033)
**Predicted under pi_15:** 0.0171 (var=0.0002)
**Predicted under pi_2:** 0.0140 (var=0.0001)

### Experiment 18
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
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
```

**Observed (real) value:** 0.4773 (var=0.0539)
**Predicted under pi_15:** 0.0123 (var=0.0004)
**Predicted under pi_2:** 0.0132 (var=0.0004)

### Experiment 19
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    tie_mask = a_wins == b_wins
    
    if not np.any(tie_mask):
        return 0.5
        
    a_tie = a_ratings[tie_mask]
    b_tie = b_ratings[tie_mask]
    responses = data['response'].values[tie_mask]
    
    ttb_preds = np.zeros(len(a_tie))
    for i in range(len(a_tie)):
        for j in range(a_tie.shape[1]):
            if a_tie[i, j] > b_tie[i, j]:
                ttb_preds[i] = 0
                break
            elif b_tie[i, j] > a_tie[i, j]:
                ttb_preds[i] = 1
                break
                
    return float(np.mean(responses == ttb_preds))
```

**Observed (real) value:** 0.5411 (var=0.0079)
**Predicted under pi_15:** 0.4844 (var=0.0061)
**Predicted under pi_2:** 0.5183 (var=0.0083)

### Experiment 20
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    match_ttb = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        # Focus only on trials where Tallying predicts a tie
        if a_wins == b_wins:
            # Determine Take-The-Best (TTB) prediction
            ttb_choice = -1
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_choice = 0
                    break
                elif b[i] > a[i]:
                    ttb_choice = 1
                    break
            
            if ttb_choice != -1:
                match_ttb.append(1.0 if row['response'] == ttb_choice else 0.0)
                
    if len(match_ttb) == 0:
        return 0.5
    return float(np.mean(match_ttb))
```

**Observed (real) value:** 0.6822 (var=0.0059)
**Predicted under pi_15:** 0.4794 (var=0.0062)
**Predicted under pi_2:** 0.4972 (var=0.0062)

### Experiment 21
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    wadd_predictions = {
        ((1, 1, 0, 0, 0), (0, 0, 1, 1, 1)): 0,
        ((0, 0, 1, 1, 1), (1, 1, 0, 0, 0)): 1,
        ((1, 0, 0, 0, 0), (0, 0, 0, 1, 1)): 0,
        ((0, 1, 0, 0, 0), (0, 0, 0, 1, 1)): 0
    }
    
    match_count = 0
    total_count = 0
    
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        if (a, b) in wadd_predictions:
            if row['response'] == wadd_predictions[(a, b)]:
                match_count += 1
            total_count += 1
            
    if total_count == 0:
        return 0.5
        
    return match_count / total_count

```

**Observed (real) value:** 0.1150 (var=0.0062)
**Predicted under pi_15:** 0.1913 (var=0.0103)
**Predicted under pi_2:** 0.1383 (var=0.0087)

### Experiment 22
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    # Identify trials where the total number of positive features is equal for A and B
    # In the experimental design, this corresponds exactly to trials 1 and 2.
    tie_trials = data[a_sums == b_sums]
    
    if len(tie_trials) == 0:
        return 0.5
        
    # Calculate the proportion of times Option A was chosen (response == 0)
    # Tallying predicts exactly 0.5 (random guessing) because the feature counts are tied.
    # WADD predicts > 0.5 because Option A possesses the higher-validity features.
    return float((tie_trials['response'] == 0).mean())
```

**Observed (real) value:** 0.3400 (var=0.0140)
**Predicted under pi_15:** 0.5100 (var=0.0125)
**Predicted under pi_2:** 0.4983 (var=0.0078)

### Experiment 23
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # Focus only on Tally-tie trials
        if np.sum(a > b) == np.sum(b > a):
            # Find the Take-The-Best (TTB) prediction
            # Validities are monotonically decreasing with index, so cue 0 is best
            for i in range(len(a)):
                if a[i] > b[i]:
                    matches.append(1 if row['response'] == 0 else 0)
                    break
                elif b[i] > a[i]:
                    matches.append(1 if row['response'] == 1 else 0)
                    break

    return float(np.mean(matches)) if matches else 0.5
```

**Observed (real) value:** 0.6178 (var=0.0052)
**Predicted under pi_15:** 0.4939 (var=0.0066)
**Predicted under pi_2:** 0.4928 (var=0.0064)

### Experiment 24
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_mat > b_mat, axis=1)
    b_wins = np.sum(b_mat > a_mat, axis=1)
    
    tie_mask = (a_wins == b_wins)
    
    if not np.any(tie_mask):
        return 0.5
        
    a_tie = a_mat[tie_mask]
    b_tie = b_mat[tie_mask]
    resp_tie = data['response'].values[tie_mask]
    
    ttb_preds = []
    for i in range(len(a_tie)):
        a = a_tie[i]
        b = b_tie[i]
        pred = 0
        for j in range(len(a)):
            if a[j] > b[j]:
                pred = 0
                break
            elif b[j] > a[j]:
                pred = 1
                break
        ttb_preds.append(pred)
        
    ttb_preds = np.array(ttb_preds)
    matches = (resp_tie == ttb_preds)
    
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5033 (var=0.0079)
**Predicted under pi_15:** 0.5104 (var=0.0056)
**Predicted under pi_2:** 0.5042 (var=0.0040)

### Experiment 25
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    mask_3 = (data['A_str'] == '11000') & (data['B_str'] == '00111')
    mask_5 = (data['A_str'] == '00111') & (data['B_str'] == '11000')
    
    chose_high_val = 0
    total = 0
    
    if mask_3.sum() > 0:
        chose_high_val += (data.loc[mask_3, 'response'] == 0).sum()
        total += mask_3.sum()
        
    if mask_5.sum() > 0:
        chose_high_val += (data.loc[mask_5, 'response'] == 1).sum()
        total += mask_5.sum()
        
    if total == 0:
        return 0.5
        
    return float(chose_high_val / total)

```

**Observed (real) value:** 0.1633 (var=0.0175)
**Predicted under pi_15:** 0.1808 (var=0.0191)
**Predicted under pi_2:** 0.1350 (var=0.0116)

### Experiment 26
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def target_chosen(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        target = (1, 1, 0, 0, 0, 0)
        alt = (0, 0, 1, 1, 1, 0)
        
        if a == target and b == alt:
            return 1.0 if row['response'] == 0 else 0.0
        elif b == target and a == alt:
            return 1.0 if row['response'] == 1 else 0.0
        return np.nan

    choices = data.apply(target_chosen, axis=1)
    val = np.nanmean(choices)
    if np.isnan(val):
        return 0.5
    return float(val)
```

**Observed (real) value:** 0.1333 (var=0.0172)
**Predicted under pi_15:** 0.1200 (var=0.0139)
**Predicted under pi_2:** 0.1533 (var=0.0176)

### Experiment 27
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # Check if it is a Tally tie
        if np.sum(a > b) == np.sum(b > a):
            # Take-The-Best prediction based on the highest validity feature (index 0)
            if a[0] > b[0]:
                matches.append(row['response'] == 0)
            elif b[0] > a[0]:
                matches.append(row['response'] == 1)
                
    if not matches:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5126 (var=0.0074)
**Predicted under pi_15:** 0.4870 (var=0.0052)
**Predicted under pi_2:** 0.5163 (var=0.0065)

### Experiment 28
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    responses = data['response'].values
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    tie_mask = (a_wins == b_wins)
    
    if not np.any(tie_mask):
        return 0.5
        
    a_tie = a_ratings[tie_mask]
    b_tie = b_ratings[tie_mask]
    resp_tie = responses[tie_mask]
    
    ttb_winners = []
    for i in range(len(a_tie)):
        winner = -1
        for j in range(5):
            if a_tie[i, j] > b_tie[i, j]:
                winner = 0
                break
            elif b_tie[i, j] > a_tie[i, j]:
                winner = 1
                break
        ttb_winners.append(winner)
        
    ttb_winners = np.array(ttb_winners)
    valid_mask = (ttb_winners != -1)
    
    if not np.any(valid_mask):
        return 0.5
        
    match = (resp_tie[valid_mask] == ttb_winners[valid_mask])
    return float(np.mean(match))
```

**Observed (real) value:** 0.5867 (var=0.0101)
**Predicted under pi_15:** 0.4963 (var=0.0046)
**Predicted under pi_2:** 0.4829 (var=0.0066)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "The observed data in both Experiment 1 and Experiment 2 violently contradict Theory 1's 'Probabilistic Least-Valid Cue Dropping' prediction. In Exp 1, Theory 1 predicted a metric > 0.5, but the observed metric was 0.1528. In Exp 2, Theory 1 predicted a positive metric, but the observed was -0.7100. A deep dive into the trial structures reveals a striking pattern: across both experiments, subjects are systematically choosing the option that has a '1' on the *last* (least valid) feature. In Exp 1, the target choices were designed such that the option with the 5th feature was usually the non-target, leading to a drastically lowered metric. In Exp 2, the option with the 5th feature was B in Trial 1 and A in Trial 2, perfectly explaining the strongly negative P(A|T1) - P(A|T2) metric. Neither pure tallying nor least-cue dropping can explain this. Instead, subjects appear to be exhibiting a massive recency effect or salience bias toward the last presented feature.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a brand-new theory based on 'Recency-Biased Cue Overweighting'. The theory should posit that while subjects may attempt to integrate features, the final feature in the sequence (despite being nominally the least valid) is highly salient due to visual recency or memory effects. Consequently, subjects disproportionately use the last feature as a primary driver of choice, effectively reversing the expected Take-The-Best hierarchy in specific boundary cases."
}
```

## Usage

```json
{
  "prompt_token_count": 22004,
  "candidates_token_count": 371,
  "total_token_count": 25429
}
```
