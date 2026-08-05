# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_6") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_6" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
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


## THEORY 2 — pi_6
Top-K Parity: Decision makers rely on a strict Cue-Parity rule but apply it selectively to a stable subset of the most valid cues. Instead of using a floating validity threshold or rounding a fraction (which can arbitrarily drop a single cue and flip the parity sum in 6- and 12-cue tasks), they evaluate the top ceil(k_frac * N) cues. This ensures that for tasks with 5 or 6 cues, all cues are evaluated, preserving multi-cue parity effects without collapsing to random parity flips.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    import math
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Top-K Parity expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    k_frac = float(parameters["k_frac"])
    
    n_cues = len(validities)
    # Use math.ceil to avoid arbitrarily dropping exactly 1 cue in 5- or 6-cue tasks
    k = max(1, math.ceil(k_frac * n_cues))
    
    # Get indices of the top K validities
    # np.argsort sorts ascending, so we take the last k elements
    top_k_indices = np.argsort(validities)[-k:]
    
    a_filtered = a[top_k_indices]
    b_filtered = b[top_k_indices]
    
    # Strict Cue-Parity on the filtered subset of cues
    a_wins = int(np.sum(a_filtered > b_filtered))
    winner = 0 if (a_wins % 2 == 1) else 1
    
    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over binary score
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

## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=20):** [0.51, 0.52, 0.53, 0.54, 0.55, 0.56, 0.57, 0.58, 0.59, 0.6, 0.61, 0.62, 0.63, 0.64, 0.65, 0.66, 0.67, 0.68, 0.69, 0.99]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 3: A=[0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 4: A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 6: A=[1, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 1, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 7: A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 8: A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]

**Rationale:** To dissociate Cue-Parity from Top-K Parity, we exploit the latter's selective exclusion of the lowest-validity cues. Top-K Parity computes parity over the top K valid features (where K is determined by k_frac in [0.9, 1.0]). For a 20-feature task, k_frac allows the model to evaluate the top 18, 19, or 20 cues, systematically dropping the 1 or 2 least valid cues. Cue-Parity, however, strictly computes parity over all 20 features. By holding the number of A-wins constant on the top 17 features (at an odd number, e.g., 5) and systematically varying whether A wins or loses on the 3 lowest-validity features, we create a matrix of trials where the parity of A-wins flips depending on exactly how many of the bottom features are included. Cue-Parity's predictions will perfectly track the parity of the full 20-feature set, while Top-K Parity's predictions will remain blind to the variations in the dropped lowest-validity features.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
By comparing the Cue-Parity match rate on trials where option A wins on the lowest-validity cue (trials 2, 4, 6, 8) versus trials where it loses (trials 1, 3, 5, 7), we can perfectly separate the two models. Cue-Parity will have a high match rate on both sets, yielding a difference near 0. Top-K Parity, which drops the lowest-validity cue half the time (when k=19), will systematically reverse its prediction on the target trials while maintaining the same prediction on control trials, yielding a strongly negative difference.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    cp_pred = (a_wins % 2 == 0).astype(int)
    
    is_target = (a_ratings[:, 0] == 1) & (b_ratings[:, 0] == 0)
    is_control = (a_ratings[:, 0] == 0) & (b_ratings[:, 0] == 1)
    
    match = (data['response'].values == cp_pred).astype(float)
    
    if np.sum(is_target) == 0 or np.sum(is_control) == 0:
        return 0.0
        
    target_match = np.mean(match[is_target])
    control_match = np.mean(match[is_control])
    
    return float(target_match - control_match)

### RESULTS
- Predicted under pi_1 (simulated): 0.0029 (var=0.0050)
- Predicted under pi_6 (simulated): -0.3800 (var=0.1608)
- Observed on real data: -0.0117 (var=0.0030)

## EXPERIMENT 2 (proposed by pi_6)

### DESIGN
**Validities (n_features=11):** [0.99, 0.95, 0.9, 0.85, 0.8, 0.75, 0.7, 0.65, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  trial 3: A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  trial 5: A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  trial 6: A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]
  trial 7: A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1]
  trial 8: A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0]

**Rationale:** To quantitatively dissociate Top-K Parity from Cue-Parity, we exploit Top-K Parity's selective dropping of the least valid cue(s). With 11 features and k_frac in [0.9, 1.0], Top-K Parity evaluates either the top 10 or all 11 features, whereas Cue-Parity always evaluates all 11. We design a full factorial matrix of trials varying the parity of A-wins on the top 10 features (Odd vs. Even) crossed with A's performance on the 11th (lowest-validity) feature (Win vs. Loss). For Cue-Parity, the 11th feature always flips the predicted choice because it changes the total parity. For Top-K Parity (when k_frac < 0.91), the 11th feature is completely ignored, resulting in identical choice probabilities regardless of whether A wins or loses on that feature.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
In an 11-feature task with k_frac ~ U(0.9, 1.0), Top-K Parity will evaluate exactly 10 cues for ~9% of subjects (when k_frac <= 0.909) and 11 cues for the rest. Cue-Parity always evaluates 11 cues. On trials where the 11th cue differs between options, 10-cue parity and 11-cue parity make strictly opposite predictions. By computing the match rate to the 10-cue parity prediction, Cue-Parity subjects will score near 0 (modulo epsilon noise), while the ~9% of Top-K Parity subjects using k=10 will score near 1. Returning the maximum subject score from the pooled dataset forces a massive difference in the point estimate (~1.0 for Top-K vs ~0.3 for Cue-Parity) while preserving tight subject-level variances, satisfying the t-test at N=25.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    subj_scores = []
    for subj, df in data.groupby('subject_id'):
        matches = []
        for _, row in df.iterrows():
            a = np.array(row['option_a_ratings'])
            b = np.array(row['option_b_ratings'])
            
            # Focus on trials where 10-cue parity differs from 11-cue parity
            # This happens exactly when the options differ on the 11th cue (index 10).
            if a[10] != b[10]:
                # Prediction if the subject drops the 11th cue (k=10)
                a_wins_10 = np.sum(a[:10] > b[:10])
                pred_10 = 0 if (a_wins_10 % 2 == 1) else 1
                matches.append(1.0 if row['response'] == pred_10 else 0.0)
                
        if matches:
            subj_scores.append(np.mean(matches))
            
    if not subj_scores:
        return 0.0
        
    # If evaluated on a single subject slice, return their individual match rate.
    if len(subj_scores) == 1:
        return float(subj_scores[0])
        
    # If evaluated on the pooled dataframe, return the maximum match rate across all subjects.
    # In Top-K Parity with n=11, k_frac in [0.9, 1.0] means ~9% of subjects will drop the 11th cue.
    # For these subjects, their match rate to 10-cue parity will be near 1.0, making the max very high.
    # In Cue-Parity, all subjects use 11 cues, so their match to 10-cue parity on these reversal trials
    # will be near 0.0 (only matching due to lapse noise), making the population max much lower.
    return float(np.max(subj_scores))

### RESULTS
- Predicted under pi_1 (simulated): 0.5521 (var=0.0011)
- Predicted under pi_6 (simulated): 0.9688 (var=0.0087)
- Observed on real data: 0.6146 (var=0.0019)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
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
**Predicted under pi_1:** 0.7083 (var=0.0555)
**Predicted under pi_6:** 0.7044 (var=0.0459)

### Experiment 4
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
**Predicted under pi_1:** 0.8596 (var=0.0092)
**Predicted under pi_6:** 0.8507 (var=0.0128)

### Experiment 5
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
**Predicted under pi_1:** 0.8479 (var=0.0101)
**Predicted under pi_6:** 0.8760 (var=0.0097)

### Experiment 6
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
**Predicted under pi_1:** 0.1700 (var=0.0169)
**Predicted under pi_6:** 0.1357 (var=0.0096)

### Experiment 7
**Design**
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Calculate the unweighted sum of cues favoring Option A (since B is all 0s)
    a_sums = data['option_a_ratings'].apply(sum)
    
    # Responses: 0 means A was chosen, 1 means B was chosen
    is_a = (data['response'] == 0).astype(float)
    is_b = (data['response'] == 1).astype(float)
    
    # For odd sums (5 and 7), Cue-Parity predicts A with equal strength.
    # For CW-Parity, sum=5 is pushed towards the half-integer dead zone by validities,
    # reducing P(A), while sum=7 is barely affected.
    p_a_7 = is_a[a_sums == 7].mean()
    p_a_5 = is_a[a_sums == 5].mean()
    
    # For even sums (4 and 6), Cue-Parity predicts B with equal strength.
    # For CW-Parity, sum=6 is pushed towards the half-integer dead zone,
    # reducing P(B), while sum=4 is unaffected.
    p_b_4 = is_b[a_sums == 4].mean()
    p_b_6 = is_b[a_sums == 6].mean()
    
    diff1 = (p_a_7 - p_a_5) if pd.notna(p_a_7) and pd.notna(p_a_5) else 0.0
    diff2 = (p_b_4 - p_b_6) if pd.notna(p_b_4) and pd.notna(p_b_6) else 0.0
    
    return float(diff1 + diff2)
```

**Observed (real) value:** 0.0525 (var=0.0125)
**Predicted under pi_1:** 0.0006 (var=0.0252)
**Predicted under pi_6:** -0.0869 (var=0.0646)

### Experiment 8
**Design**
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    a_wins_mask = (a_ratings > b_ratings).astype(int)
    a_wins = a_wins_mask.sum(axis=1)
    high_wins = a_wins_mask[:, :5].sum(axis=1)
    
    # T1, T2: 5 wins, strictly uniform validities
    mask_12 = (a_wins == 5) & ((high_wins == 0) | (high_wins == 5))
    
    # T3, T4: 4 wins, strictly uniform validities
    mask_34 = (a_wins == 4) & ((high_wins == 0) | (high_wins == 4))
    
    if mask_12.sum() == 0 or mask_34.sum() == 0:
        return 0.0
        
    # h is the number of times Option A was chosen
    h_12 = (data['response'].values[mask_12] == 0).sum()
    m_12 = mask_12.sum() - h_12
    
    h_34 = (data['response'].values[mask_34] == 0).sum()
    m_34 = mask_34.sum() - h_34
    
    # Compute log-odds of choosing A with Laplace smoothing
    lo_12 = np.log((h_12 + 0.5) / (m_12 + 0.5))
    lo_34 = np.log((h_34 + 0.5) / (m_34 + 0.5))
    
    # We return the negative sum of these log-odds
    return float(-(lo_12 + lo_34))
```

**Observed (real) value:** -0.1572 (var=0.8155)
**Predicted under pi_1:** 0.1336 (var=1.0828)
**Predicted under pi_6:** 0.1055 (var=1.0315)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['b_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1_mask = (data['a_str'] == '10000') & (data['b_str'] == '00000')
    t2_mask = (data['a_str'] == '00010') & (data['b_str'] == '11100')
    t3_mask = (data['a_str'] == '11000') & (data['b_str'] == '00000')
    t4_mask = (data['a_str'] == '00011') & (data['b_str'] == '11100')
    
    p_a_t1 = 1.0 - data.loc[t1_mask, 'response'].mean()
    p_a_t2 = 1.0 - data.loc[t2_mask, 'response'].mean()
    p_a_t3 = 1.0 - data.loc[t3_mask, 'response'].mean()
    p_a_t4 = 1.0 - data.loc[t4_mask, 'response'].mean()
    
    diff1 = (p_a_t1 - p_a_t2) if pd.notna(p_a_t1) and pd.notna(p_a_t2) else 0.0
    diff2 = (p_a_t3 - p_a_t4) if pd.notna(p_a_t3) and pd.notna(p_a_t4) else 0.0
    
    return float(diff1 + diff2)
```

**Observed (real) value:** 0.0250 (var=0.0422)
**Predicted under pi_1:** -0.0625 (var=0.0234)
**Predicted under pi_6:** -0.0475 (var=0.0229)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Identify the trial types based on option A's features.
    # T1: sum=1, A[0]=1 (Parity favors A, Tally favors A)
    # T2: sum=1, A[0]=0 (Parity favors A, Tally favors B)
    # T3: sum=2, A[0]=1 (Parity favors B, Tally favors A)
    # T4: sum=2, A[0]=0 (Parity favors B, Tally favors B)
    # T5: sum=3, A[0]=1 (Parity favors A, Tally favors A)
    # T6: sum=3, A[0]=0 (Parity favors A, Tally favors B)
    
    def get_trial_type(row):
        a = row['option_a_ratings']
        s = sum(a)
        if s == 1:
            return 'T1' if a[0] == 1 else 'T2'
        elif s == 2:
            return 'T3' if a[0] == 1 else 'T4'
        elif s == 3:
            return 'T5' if a[0] == 1 else 'T6'
        return 'Other'
        
    data = data.copy()
    data['trial_type'] = data.apply(get_trial_type, axis=1)
    data['chose_A'] = (data['response'] == 0).astype(float)
    
    # Calculate mean P(choose A) for each trial type
    means = data.groupby('trial_type')['chose_A'].mean()
    
    def get_mean(t):
        return means.get(t, 0.0)
        
    # Difference in P(choose A) when Tally favors A vs when Tally favors B,
    # holding Parity constant.
    diff_1 = get_mean('T1') - get_mean('T2')
    diff_2 = get_mean('T3') - get_mean('T4')
    diff_3 = get_mean('T5') - get_mean('T6')
    
    return float(diff_1 + diff_2 + diff_3)

```

**Observed (real) value:** 0.1067 (var=0.0581)
**Predicted under pi_1:** -0.0017 (var=0.0649)
**Predicted under pi_6:** -0.0217 (var=0.0513)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across both new experiments, Theory 1 (Cue-Parity) captures the observed data much better than Theory 2 (Top-K Parity). In Experiment 1, Top-K Parity predicts a strong negative difference (-0.38) because it drops the lowest validity cues, but the observed data is near zero (-0.0117), perfectly matching Cue-Parity. In Experiment 2, Top-K Parity predicts a near 1.0 match rate for the 10-cue subset, but the observed data (0.61) is much closer to Cue-Parity's prediction (0.55). However, looking at older experiments (especially 8 and 10), both pure parity models fail to capture the positive effect of Tally / Validity when parity is held constant. The observed data in Exp 10 shows a positive difference (0.1067), indicating that subjects use tally or validity weights, whereas both parity models predict ~0.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Parity-Compensatory Mixture' theory. The decision maker does not rely exclusively on parity. Instead, they compute both the parity of the winning cues (which drives the strong effects in Exps 1-5) and a standard compensatory tally or validity-weighted sum (which drives the effects in Exps 8 and 10). The final choice probability should be a mixture or a weighted combination of the Parity rule's prediction and a Softmax over the validity-weighted evidence. This will allow the model to capture both the non-monotone parity behavior and the monotonic tally/validity effects observed when parity is held constant."
}
```

## Usage

```json
{
  "prompt_token_count": 12289,
  "candidates_token_count": 384,
  "total_token_count": 13751
}
```
