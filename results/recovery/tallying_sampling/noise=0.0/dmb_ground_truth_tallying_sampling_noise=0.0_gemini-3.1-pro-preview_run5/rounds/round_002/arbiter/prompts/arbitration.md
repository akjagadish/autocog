# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
Tallying (Equal Weight) theory posits that decision-makers simply count the number of positive features (or cues) for each option and choose the option with the higher tally, ignoring cue validities completely. This is a compensatory heuristic that treats all pieces of evidence equally.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    # Stimulus is the pair of option feature vectors for the current trial
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    # Tallying: count the number of positive features for each option
    scores = np.sum(stim, axis=1)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Add uniform lapse rate
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_4
Soft Threshold Tallying posits that decision-makers use a compensatory tallying heuristic, but down-weight cues that are less reliable. They evaluate each feature's subjective validity against a personal threshold using a smooth sigmoid function, creating a soft inclusion mask. Features that fall well below the threshold are effectively ignored, while those above are tallied with near-equal weight. This smooth transition provides a bridge between pure equal-weight tallying and selective attention to high-validity information, while allowing for continuous optimization.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Threshold Tallying expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    threshold = float(parameters["threshold"])
    steepness = float(parameters["steepness"])
    
    # Soft threshold using a logistic sigmoid to create a smooth inclusion mask
    weights = 1.0 / (1.0 + np.exp(-steepness * (validities - threshold)))
    
    # Tally the features weighted by the soft threshold mask
    scores = np.sum(stim * weights, axis=1)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Add uniform lapse rate
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.98, 0.92, 0.65, 0.55, 0.51]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 3: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 5: A=[0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 6: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 7: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 8: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To effectively dissociate pure Tallying from Soft Threshold Tallying, we use a 5-feature design with a pronounced gap between high and low validities. Pure Tallying simply counts the positive features, remaining completely indifferent to their validities. Soft Threshold Tallying, by contrast, applies a sigmoid threshold mask that heavily down-weights or eliminates low-validity features. The trial set includes pairs where an option with fewer but highly valid features competes against an option with more but lower-validity features (causing opposing predictions), as well as pairs with equal feature counts but differing validities (causing Tallying to be indifferent while Soft Threshold Tallying shows a strong preference).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Pure Tallying predicts that the probability of choosing the option with more features depends entirely on the difference in feature counts. In this design, 7 out of the 8 unique trial pairs have a feature count difference of exactly 1. Therefore, Pure Tallying dictates that the true probability of choosing the option with more features is mathematically identical across all 7 of these trial pairs. Any variation in a subject's choice proportions across these 7 pairs is purely due to binomial sampling noise, resulting in a tightly bounded, very small variance. Soft Threshold Tallying, however, down-weights low-validity features. Consequently, its true probability of choosing the option with more features will vary drastically across these 7 pairs (depending on whether the extra features happen to be high or low validity). By computing the within-subject sample variance of the choice proportions across these 7 trial pairs, we obtain a metric that is structurally constrained to be near zero for Pure Tallying, but significantly positive for Soft Threshold Tallying, perfectly isolating the divergence.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    responses = data['response'].values
    subjects = data['subject_id'].values
    
    count_a = a_ratings.sum(axis=1)
    count_b = b_ratings.sum(axis=1)
    
    # Filter out trials where both options have the same number of positive features
    mask = count_a != count_b
    if not np.any(mask):
        return 0.0
        
    a_ratings = a_ratings[mask]
    b_ratings = b_ratings[mask]
    responses = responses[mask]
    subjects = subjects[mask]
    count_a = count_a[mask]
    count_b = count_b[mask]
    
    # Binary indicator: did the subject choose the option with MORE positive features?
    chose_more = (((count_a > count_b) & (responses == 0)) | 
                  ((count_b > count_a) & (responses == 1))).astype(float)
                  
    # Create order-independent string keys for each unique trial pair
    a_str = np.array([''.join([str(int(x)) for x in row]) for row in a_ratings])
    b_str = np.array([''.join([str(int(x)) for x in row]) for row in b_ratings])
    keys = np.where(a_str < b_str, a_str + "_" + b_str, b_str + "_" + a_str)
    
    subject_metrics = []
    for subj in np.unique(subjects):
        subj_mask = subjects == subj
        subj_keys = keys[subj_mask]
        subj_chose_more = chose_more[subj_mask]
        
        unique_keys = np.unique(subj_keys)
        if len(unique_keys) < 2:
            continue
            
        # For each unique trial pair, calculate the proportion of times 
        # the subject chose the option with more features
        means = []
        for k in unique_keys:
            k_mask = subj_keys == k
            means.append(np.mean(subj_chose_more[k_mask]))
            
        # Compute the variance of these choice proportions across the different trial pairs
        subject_metrics.append(np.var(means, ddof=1))
        
    if not subject_metrics:
        return 0.0
        
    return float(np.mean(subject_metrics))

### RESULTS
- Predicted under pi_3 (simulated): 0.0074 (var=0.0001)
- Predicted under pi_4 (simulated): 0.0188 (var=0.0017)
- Observed on real data: 0.0096 (var=0.0001)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 6: A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 7: A=[0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 8: A=[0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0]

**Rationale:** This design uses a 5-feature environment with two highly valid features and three low-validity features to create a sharp divergence between Tallying and Soft Threshold Tallying. Pure Tallying weights all features equally, choosing the option with the most positive features. Soft Threshold Tallying applies a sigmoid threshold that effectively masks out the low-validity features, causing choices to be driven predominantly by the high-validity features. The trial pairs systematically pit options with fewer high-validity features against options with more low-validity features, leading to strictly opposing predictions. We also include trials where Tallying is indifferent but Soft Threshold Tallying has a strong preference.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Equal Weight Tallying evaluates Trials 4 and 8 as perfect ties (3 vs 3 features), predicting P(A)=0.5 for both, making `P(A|T4) - P(A|T8)` exactly 0 in expectation. Soft Threshold Tallying behaves identically to Tallying for roughly 90% of its parameter space (when the threshold is too low to mask out features), which washes out mean-based contrasts. However, for the ~10% of subjects with a high threshold, STT strongly prefers A in Trial 4 and B in Trial 8, pushing this difference toward +1.0. By evaluating the maximum of this difference across subjects on the pooled data, we explicitly target the right tail of the STT parameter distribution. Tallying will yield a low maximum driven purely by binomial noise, while STT will yield a massive spike near 1.0, cleanly breaking the models apart.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    scores = []
    for subj, df_subj in data.groupby('subject_id'):
        a_str = df_subj['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
        b_str = df_subj['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
        
        # Trial 4: A=[1, 1, 1, 0, 0] vs B=[0, 0, 1, 1, 1] (Sums: 3 vs 3)
        t4 = (a_str == "11100") & (b_str == "00111")
        # Trial 8: A=[0, 0, 1, 1, 1] vs B=[1, 1, 1, 0, 0] (Sums: 3 vs 3)
        t8 = (a_str == "00111") & (b_str == "11100")
        
        p_a_t4 = df_subj.loc[t4, 'response'].eq(0).mean() if t4.any() else 0.5
        p_a_t8 = df_subj.loc[t8, 'response'].eq(0).mean() if t8.any() else 0.5
        
        # Tallying predicts exactly 0.5 for both, so the expected difference is 0.
        # Soft Threshold Tallying prioritizes the high-validity features, so 
        # P(A|T4) will be high and P(A|T8) will be low, yielding a positive score.
        scores.append(p_a_t4 - p_a_t8)
        
    # Because STT behaves identically to Tallying for the majority of its parameter 
    # space (when threshold < 0.5), the mean difference is diluted. 
    # By extracting the maximum score across the pooled subjects, we directly isolate 
    # the sub-population of STT subjects with active thresholds, guaranteeing a massive 
    # statistical divergence from Tallying's binomial noise ceiling.
    if len(scores) > 1:
        return float(np.max(scores))
    elif len(scores) == 1:
        return float(scores[0])
    else:
        return 0.0

### RESULTS
- Predicted under pi_3 (simulated): 0.4167 (var=0.0362)
- Predicted under pi_4 (simulated): 1.0000 (var=0.0867)
- Observed on real data: 0.5000 (var=0.0594)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Calculate the sum of positive features for options A and B
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Determine which option has the fewer number of positive features.
    # Since there are no ties in the sum of features in this design,
    # we can simply check if sum_a > sum_b. If true, B (1) has fewer features;
    # if false, A (0) has fewer features.
    smaller_option = (sum_a > sum_b).astype(int)
    
    # Check if the subject's response matches the option with fewer features
    match = (data['response'] == smaller_option).astype(float)
    
    return float(match.mean())
```

**Observed (real) value:** 0.1546 (var=0.0058)
**Predicted under pi_3:** 0.1429 (var=0.0080)
**Predicted under pi_4:** 0.1504 (var=0.0107)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = 0
    total = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_winner = -1
        for j in range(5):
            if a[j] > b[j]:
                ttb_winner = 0
                break
            elif b[j] > a[j]:
                ttb_winner = 1
                break
                
        if ttb_winner != -1:
            if resp == ttb_winner:
                matches += 1
            total += 1
            
    return float(matches / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.2791 (var=0.0051)
**Predicted under pi_3:** 0.2791 (var=0.0029)
**Predicted under pi_4:** 0.3047 (var=0.0069)

### Experiment 5
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Identify critical trials where Tallying and WADD make opposite predictions.
    # Tallying prefers the option with more features (3 features).
    # WADD prefers the option with fewer but higher-validity features (2 features).
    is_t1 = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1)) & \
            data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))
            
    is_t2 = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0)) & \
            data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
            
    # Tallying chooses A on t1 (response 0) and B on t2 (response 1)
    t1_tally_choices = (data.loc[is_t1, 'response'] == 0).sum()
    t2_tally_choices = (data.loc[is_t2, 'response'] == 1).sum()
    
    total_critical = is_t1.sum() + is_t2.sum()
    if total_critical == 0:
        return 0.5
        
    return float((t1_tally_choices + t2_tally_choices) / total_critical)
```

**Observed (real) value:** 0.8289 (var=0.0141)
**Predicted under pi_3:** 0.8489 (var=0.0138)
**Predicted under pi_4:** 0.7856 (var=0.0577)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    mask_t2 = a_str == '11000'
    mask_t3 = a_str == '00111'
    
    p_a_t2 = (data.loc[mask_t2, 'response'] == 0).mean() if mask_t2.any() else 0.5
    p_a_t3 = (data.loc[mask_t3, 'response'] == 0).mean() if mask_t3.any() else 0.5
    
    return float(p_a_t2 - p_a_t3)
```

**Observed (real) value:** -0.7833 (var=0.0417)
**Predicted under pi_3:** -0.7400 (var=0.0307)
**Predicted under pi_4:** -0.5950 (var=0.1389)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Theory 1 (Pure Tallying) consistently outperforms Theory 2 (Soft Threshold Tallying) across all experiments. The observed data strongly suggests that subjects are largely ignoring cue validities and simply counting the number of positive features. Theory 1's predictions closely match the observed values, especially in Experiment 2 where Theory 2 expected a massive spike (1.0000) that did not materialize (observed: 0.5000). Theory 2's attempt to smoothly down-weight low-validity features pulls its predictions away from the empirical reality. Because Pure Tallying is such a dominant explanation, we should replace Theory 2 with a new, highly competitive theory that builds upon the success of Tallying but introduces a different mechanism for handling edge cases.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Tallying with Lexicographic Tie-Breaking' theory. This theory should posit that subjects primarily use a compensatory equal-weight tallying heuristic (which explains the vast majority of the variance). However, when the tallies are tied, instead of guessing randomly, they break the tie by comparing the options on the single most valid feature (a Take-The-Best mechanism). This provides a strong competitor to Pure Tallying because it perfectly mimics Tallying on unequal counts, but offers a deterministic, validity-based resolution for ties."
}
```

## Usage

```json
{
  "prompt_token_count": 7329,
  "candidates_token_count": 315,
  "total_token_count": 8941
}
```
