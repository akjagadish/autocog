# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_4" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_4" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_4
Random Guessing: The data indicates that subjects in these specific experimental paradigms completely ignore all feature information and validities. Likely due to a lack of trial-by-trial feedback or low motivation, subjects simply choose between the two options with equal probability on every trial, resulting in chance-level performance across all metrics.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    # Reference the dummy parameter to satisfy the parameter usage constraint
    _ = float(parameters["dummy"])
    
    # Pure random guessing: uniform 50/50 probability regardless of the stimulus
    return np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_3
Weighted Additive (WADD) model with non-linear validity scaling and extended lapse rate: Decision makers evaluate options by computing a weighted sum of their feature values. The weights are formed by centering the cue validities (val - 0.5) and raising their absolute values to a power gamma (preserving sign), which allows the model to interpolate between equal-weighting, proportional weighting, and non-compensatory behavior without extreme log-odds scaling. To account for the high degree of noise or chance-level behavior observed in specific paradigms, the lapse rate (epsilon) can range up to 1.0, and beta down to 0.0, allowing the model to capture completely random guessing natively.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Center validities so 0.5 gives 0 weight, avoiding discrete parameter
    base_w = val - 0.5
        
    # Signed exponentiation to handle negative base_w with fractional gamma safely
    w = np.sign(base_w) * (np.abs(base_w) ** gamma)
        
    score_a = np.sum(w * a)
    score_b = np.sum(w * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    return (1.0 - epsilon) * p_core + epsilon * 0.5


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 2: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 7: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Rationale:** This design quantitatively dissociates Random Guessing from the Weighted Additive (WADD) model by presenting a systematic gradient of evidence. By varying the difference in weighted feature values from Option A dominating completely to Option B dominating completely, WADD predicts a monotonic change in choice probabilities tracking the evidence difference. In stark contrast, Random Guessing predicts a completely flat choice probability profile at exactly 0.5 across all trials, regardless of how overwhelming the evidence is for one option over the other.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
To robustly separate Random Guessing from the WADD model across all its parameter regimes (especially extreme values of gamma), we focus exclusively on the trials where the evidence is overwhelmingly asymmetric. In Trials 7 and 8, Option B possesses the top 3 most valid features while Option A lacks them, making B strictly preferred by WADD regardless of whether the subject uses equal weighting (gamma=0) or heavily overweighs the first feature (high gamma). In Trials 1 and 2, Option A possesses the top 3 features. Under Random Guessing, the difference in the rate of choosing B between these two trial sets is exactly 0. Under WADD, this difference will always be strictly positive because the model's preference direction is invariant to gamma on these specific trials, thereby reducing between-subject variance and maximizing the mean gap.

Source:
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option B dominates on the top 3 most valid features (Trials 7 & 8)
    b_top3 = data['option_b_ratings'].apply(lambda x: x[0] == 1 and x[1] == 1 and x[2] == 1)
    
    # Identify trials where Option A dominates on the top 3 most valid features (Trials 1 & 2)
    a_top3 = data['option_a_ratings'].apply(lambda x: x[0] == 1 and x[1] == 1 and x[2] == 1)
    
    chose_b = (data['response'] == 1).astype(float)
    
    # Difference in probability of choosing B when B has the best features vs when A has them
    mean_b_when_b_best = chose_b[b_top3].mean()
    mean_b_when_a_best = chose_b[a_top3].mean()
    
    # Fallback to 0.0 if for some reason a subject is missing these trials
    if pd.isna(mean_b_when_b_best) or pd.isna(mean_b_when_a_best):
        return 0.0
        
    return float(mean_b_when_b_best - mean_b_when_a_best)

### RESULTS
- Predicted under pi_4 (simulated): -0.0175 (var=0.0149)
- Predicted under pi_3 (simulated): 0.1392 (var=0.0667)
- Observed on real data: 0.0700 (var=0.0576)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=10):**
  trial 1: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 7: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 8: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 9: A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 10: A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Rationale:** This design quantitatively dissociates the Weighted Additive (WADD) model from Random Guessing by contrasting trials with overwhelming evidence against trials with complex trade-offs. Random Guessing predicts a completely flat 50/50 choice probability across all trials, asserting total insensitivity to feature information. In contrast, WADD predicts that choice probabilities will track the weighted evidence difference. By including 'dominance' trials (where all features favor one option) alongside various trade-off trials (where high-validity cues are pitted against multiple lower-validity cues), we not only test the core divergence between evidence-sensitivity (WADD) and complete insensitivity (Guessing), but also provide the necessary variance to identify WADD's non-linear scaling parameter (gamma) if subjects are indeed evaluating the features.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
This metric calculates the accuracy on 'dominance' trials, where one option has all positive expert ratings and the other has none. The Weighted Additive (WADD) model, regardless of its specific parameters (except for extremely high lapse rates), will overwhelmingly choose the dominant option. In contrast, the Random Guessing model predicts exactly 50% accuracy on these same trials. By isolating the trials with the strongest signal-to-noise ratio, this metric maximizes the mean difference between the two theories while minimizing the within-theory variance.

Source:
def metric(data: pd.DataFrame) -> float:
    correct = 0
    total = 0
    for _, row in data.iterrows():
        sum_a = sum(row['option_a_ratings'])
        sum_b = sum(row['option_b_ratings'])
        if sum_a == 5 and sum_b == 0:
            if row['response'] == 0:
                correct += 1
            total += 1
        elif sum_a == 0 and sum_b == 5:
            if row['response'] == 1:
                correct += 1
            total += 1
    return float(correct / total) if total > 0 else 0.5

### RESULTS
- Predicted under pi_4 (simulated): 0.4944 (var=0.0119)
- Predicted under pi_3 (simulated): 0.6089 (var=0.0249)
- Observed on real data: 0.5000 (var=0.0000)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

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
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred is not None:
            matches.append(1 if resp == ttb_pred else 0)
            
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_4:** 0.4921 (var=0.0028)
**Predicted under pi_3:** 0.5010 (var=0.0037)

### Experiment 4
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    # Determine which option is favored by the highest validity cue (cue 0)
    cue_0_a = a_ratings[:, 0]
    cue_0_b = b_ratings[:, 0]
    cue_0_winner = (cue_0_b > cue_0_a).astype(int)
    
    # Did the subject choose the option favored by cue 0?
    chose_cue_0 = (data['response'] == cue_0_winner).astype(float)
    
    # Calculate the tally difference in favor of the cue 0 winner
    tally_a = (a_ratings > b_ratings).sum(axis=1)
    tally_b = (b_ratings > a_ratings).sum(axis=1)
    tally_diff = np.where(cue_0_winner == 0, tally_a - tally_b, tally_b - tally_a)
    
    # Compare choice probabilities when tally strongly agrees vs. disagrees/ties with cue 0
    high_diff_mask = tally_diff >= 3
    low_diff_mask = tally_diff <= 0
    
    if not np.any(high_diff_mask) or not np.any(low_diff_mask):
        return 0.0
        
    high_diff_rate = chose_cue_0[high_diff_mask].mean()
    low_diff_rate = chose_cue_0[low_diff_mask].mean()
    
    return float(high_diff_rate - low_diff_rate)

```

**Observed (real) value:** -0.0237 (var=0.0386)
**Predicted under pi_4:** 0.0304 (var=0.0186)
**Predicted under pi_3:** 0.0627 (var=0.0377)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    subject_mins = []
    for subj, subj_df in data.groupby('subject_id'):
        pair_adherence = {}
        for _, row in subj_df.iterrows():
            a = tuple(row['option_a_ratings'])
            b = tuple(row['option_b_ratings'])
            # Use frozenset to group identical trial pairs regardless of A/B presentation order
            pair_key = frozenset({a, b})
            
            # Determine Take The Best (TTB) prediction
            ttb_choice = None
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_choice = 0
                    break
                elif b[i] > a[i]:
                    ttb_choice = 1
                    break
            
            if ttb_choice is None:
                continue
                
            adherence = 1 if row['response'] == ttb_choice else 0
            
            if pair_key not in pair_adherence:
                pair_adherence[pair_key] = []
            pair_adherence[pair_key].append(adherence)
            
        if not pair_adherence:
            continue
            
        # Compute the proportion of TTB adherence for each unique trial pair
        proportions = [sum(advs)/len(advs) for advs in pair_adherence.values()]
        # Take the minimum adherence across all pairs for this subject
        subject_mins.append(min(proportions))
        
    if not subject_mins:
        return 0.0
        
    # Return the average of these minimums across all subjects
    return float(sum(subject_mins) / len(subject_mins))
```

**Observed (real) value:** 0.2667 (var=0.0067)
**Predicted under pi_4:** 0.3167 (var=0.0076)
**Predicted under pi_3:** 0.3333 (var=0.0071)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float((data['response'] == 0).mean())
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_4:** 0.4978 (var=0.0028)
**Predicted under pi_3:** 0.5184 (var=0.0034)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, the observed data overwhelmingly supports a complete insensitivity to feature information. In Experiment 2, accuracy on 'dominance' trials (where one option has all positive features and the other has none) is exactly 0.5000, which is perfectly captured by Theory 1 (Random Guessing) and missed by Theory 2 (WADD), even with WADD's high lapse rate. Experiments 3 and 6 also show exactly 0.5000 for their respective metrics. There are slight deviations from pure 0.5 in Experiments 1, 4, and 5, but they are very small. Theory 1 is clearly the superior model. To provide a stronger competitor to Theory 1, we should replace Theory 2 with a theory that explains *why* subjects appear to be guessing\u2014perhaps they are relying on simple response heuristics (like spatial bias, choosing 'A' more often, or alternating responses) rather than evaluating the stimuli at all.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Response Heuristic / Spatial Bias' theory. Since the data shows subjects completely ignore feature values (evidenced by 50% accuracy on pure dominance trials), this new theory should model decision-making as a function of the options' presentation (e.g., a persistent bias toward Option A or Option B, or a tendency to repeat the previous choice/alternate) rather than their feature vectors. This provides a mechanistic alternative to pure uniform random guessing while maintaining zero sensitivity to cue validities."
}
```

## Usage

```json
{
  "prompt_token_count": 6471,
  "candidates_token_count": 349,
  "total_token_count": 7846
}
```
