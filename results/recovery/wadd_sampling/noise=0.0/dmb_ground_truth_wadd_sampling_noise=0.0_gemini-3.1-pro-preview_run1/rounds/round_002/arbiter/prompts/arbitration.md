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
Weighted Additive (WADD) strategy: Decision-makers evaluate options by integrating all available information, computing a weighted sum of the features for each option where the weights are the cue validities. This compensatory approach balances the number of features an option possesses against the importance (validity) of those features.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    score_a = np.dot(a, val)
    score_b = np.dot(b, val)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
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
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_4
Non-linear Rank-Weighted Additive Strategy: Decision-makers evaluate options by integrating all available features, but weight them by a non-linear transformation of their ordinal rank of importance. By scaling the ranks by a power parameter gamma, the decision-maker can smoothly interpolate between pure Tallying (gamma=0, where all features are weighted equally) and steeper rank-based weighting (gamma>1). This flexibility allows the model to capture the observed ~0.50 split in conflict trials by balancing the sums of top versus bottom feature ranks appropriately.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    from scipy.stats import rankdata
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    
    # rankdata assigns rank 1 to the smallest value. 
    # Thus, higher validity gets a proportionally higher integer rank (weight).
    gamma = float(parameters["gamma"])
    weights = rankdata(val) ** gamma
    
    score_a = np.dot(a, weights)
    score_b = np.dot(b, weights)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
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
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.8, 0.75, 0.5]

**Trial pairs (n=5):**
  trial 1: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 3: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 4: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 5: A=[1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1]

**Rationale:** To dissociate the Weighted Additive (WADD) strategy from the Non-linear Rank-Weighted Additive Strategy, we exploit the difference between true cue validities and their ordinal ranks. We use a set of validities where the top cues are closely clustered in validity, followed by a sharp drop-off to the lowest cue. WADD's compensatory sums will reflect these specific quantitative differences (e.g., heavily penalizing the lowest validity cue and treating the top ones as nearly interchangeable). In contrast, the rank-based model enforces a rigid ordinal structure (ranks 5, 4, 3, 2, 1) and scales them by a parameter gamma. This forces the rank model to either predict ties (when rank sums are equal, gamma=1), heavily favor the single highest-ranked cue (gamma > 1), or approximate tallying (gamma < 1), consistently failing to match WADD's continuous validity-summation in specific conflict trials.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times subjects chose Option A in specific trials (Trials 2, 3, and 5). In these trials, the Weighted Additive (WADD) strategy consistently prefers Option B because its compensatory sum of validities is substantially higher than Option A's. Conversely, the Non-linear Rank-Weighted Additive Strategy (with gamma varying between 0 and 2) will often predict a tie (when gamma=1) or even a strong preference for Option A (when gamma > 1), because the rank-based weighting amplifies the top-ranked cues in A without reflecting the small actual validity differences. Consequently, the mean rate of choosing A will be significantly higher and more variable under the Rank theory compared to the consistently low rate predicted by WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    target_trials = {
        ('10000', '00110'),
        ('01001', '00110'),
        ('10001', '00111')
    }
    
    combined = list(zip(a_str, b_str))
    mask = [pair in target_trials for pair in combined]
    
    if sum(mask) == 0:
        return 0.0
        
    return float((data.loc[mask, 'response'] == 0).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.1909 (var=0.0154)
- Predicted under pi_4 (simulated): 0.4846 (var=0.0866)
- Observed on real data: 0.3593 (var=0.0448)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.85, 0.8, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 2: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 4: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  trial 5: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 7: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 8: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** To dissociate the non-linear Rank-Weighted Additive Strategy from the standard Weighted Additive (WADD) model, we exploit the difference between true cue validities and their ordinal ranks. We use a set of validities where the top cues are closely clustered (e.g., 0.95, 0.90, 0.85, 0.80) with a drop-off to the lowest cue (0.50). WADD's compensatory sums will reflect these specific quantitative differences, often favoring an option with two closely-matched high-validity cues over an option with the single highest validity cue plus the lowest validity cue. In contrast, the rank-based model scales the integer ranks (5, 4, 3, 2, 1) by a power parameter gamma. When gamma > 1, the rank weights grow non-linearly, causing the highest-ranked cue to dominate. This allows the Rank-Weighted model to prefer options that WADD strictly rejects, providing a clear quantitative dissociation.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
In Trials 6 and 7, WADD strongly prefers option B because the sum of validities for B is much higher than for A (e.g., 2.15 vs 1.85, and 2.2 vs 1.8). However, the Rank-Weighted Additive Strategy, which transforms the validities into ranks (5, 4, 3, 2, 1) and scales them by a non-linear parameter gamma, assigns a higher score to option A for almost all values of gamma > 0.5. By measuring the proportion of times a subject chooses option A on these specific trials, we can cleanly discriminate between the linear compensatory nature of WADD (which yields a value near 0) and the rank-based prioritization of the advocated theory (which yields a significantly higher value).

Source:
def metric(data: pd.DataFrame) -> float:
    a_ratings = data['option_a_ratings'].apply(tuple)
    mask = (a_ratings == (1, 1, 0, 0, 0)) | (a_ratings == (1, 0, 1, 0, 0))
    subset = data[mask]
    if len(subset) == 0:
        return 0.5
    return float((subset['response'] == 0).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.2000 (var=0.0156)
- Predicted under pi_4 (simulated): 0.6967 (var=0.0834)
- Observed on real data: 0.4667 (var=0.0658)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def get_ttb_choice(a, b):
        for i in range(len(a)):
            if a[i] > b[i]:
                return 0
            elif b[i] > a[i]:
                return 1
        return -1

    ttb_choices = [get_ttb_choice(a, b) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    
    matches = (data['response'] == ttb_choices)
    return float(matches.mean())
```

**Observed (real) value:** 0.2758 (var=0.0200)
**Predicted under pi_3:** 0.1548 (var=0.0068)
**Predicted under pi_4:** 0.3375 (var=0.0395)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_ttb_match(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        for j in range(len(a)):
            if a[j] > b[j]:
                return resp == 0
            elif b[j] > a[j]:
                return resp == 1
        return False
        
    return float(data.apply(is_ttb_match, axis=1).mean())
```

**Observed (real) value:** 0.2825 (var=0.0090)
**Predicted under pi_3:** 0.2298 (var=0.0054)
**Predicted under pi_4:** 0.3419 (var=0.0265)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    wadd_aligned = []
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        # Trial type 1: A has the 2 high-validity features, B has the 3 low-validity features
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            wadd_aligned.append(1.0 if resp == 0 else 0.0)
        # Trial type 2: Flipped
        elif a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            wadd_aligned.append(1.0 if resp == 1 else 0.0)
            
    if len(wadd_aligned) == 0:
        return 0.5
    return float(np.mean(wadd_aligned))
```

**Observed (real) value:** 0.5083 (var=0.0801)
**Predicted under pi_3:** 0.7700 (var=0.0188)
**Predicted under pi_4:** 0.6683 (var=0.1086)

### Experiment 6
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    tallying_consistent = 0
    total = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            if resp == 0:
                tallying_consistent += 1
            total += 1
        elif a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            if resp == 1:
                tallying_consistent += 1
            total += 1
            
    if total == 0:
        return 0.5
    return tallying_consistent / total
```

**Observed (real) value:** 0.3446 (var=0.0522)
**Predicted under pi_3:** 0.2100 (var=0.0133)
**Predicted under pi_4:** 0.3185 (var=0.0896)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the six experiments, the observed data generally falls between the predictions of the Weighted Additive (WADD) model (Theory 1) and the Non-linear Rank-Weighted model (Theory 2). For instance, in Experiment 1 and 2, the observed metric is roughly halfway between the two theories. In Experiment 6, Theory 2 accurately predicts the proportion of tallying-consistent choices, but in Experiment 5, both models overshoot the observed chance-level behavior (0.51). The consistent failure of pure compensatory WADD (Theory 1) to match the high variance and intermediate choice rates suggests that subjects are not uniformly integrating all weighted features. Theory 2's rank-based approach is closer but still misses the mark on several conflict trials.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a bounded rationality 'Strategy Mixture' theory. Instead of assuming all subjects use a compensatory mechanism (like WADD or Rank-WADD), this theory should posit that the population consists of a mixture of decision-makers using fast-and-frugal heuristics: a proportion uses 'Take-The-Best' (Lexicographic, stopping at the first discriminating cue) and the remainder uses 'Tallying' (unweighted sum of features). This mixture would naturally produce the intermediate choice probabilities and higher variance observed across the conflict trials, bridging the gap between WADD's strict preferences and the observed data."
}
```

## Usage

```json
{
  "prompt_token_count": 5911,
  "candidates_token_count": 323,
  "total_token_count": 7221
}
```
