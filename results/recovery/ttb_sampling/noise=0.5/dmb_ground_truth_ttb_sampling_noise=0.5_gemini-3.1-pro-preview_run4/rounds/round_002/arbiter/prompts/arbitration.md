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
People use a non-compensatory heuristic called 'Take The Best' (TTB) to choose between options. They search through features in descending order of subjective validity, stopping at the first feature that discriminates between the two options, and choose the option with the higher value on that feature. If no features discriminate, they guess randomly.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    a_wins = 0.0
    b_wins = 0.0
    
    # Search for the first discriminating feature
    for idx in order:
        if a[idx] > b[idx]:
            a_wins = 1.0
            break
        elif b[idx] > a[idx]:
            b_wins = 1.0
            break
            
    # If no feature discriminates, baseline preference is uniform
    if a_wins == 0.0 and b_wins == 0.0:
        p_core = np.array([0.5, 0.5])
    else:
        p_core = np.array([a_wins, b_wins])
        
    epsilon = float(parameters["epsilon"])
    n_opts = p_core.shape[0]
    
    # Apply lapse rate
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_4
Stochastic Take-The-Best (Search Error)

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Search through features in descending order of validity
    order = np.argsort(validities)[::-1]
    
    p_skip = float(parameters["p_skip"])
    epsilon = float(parameters["epsilon"])
    
    p_A_core = 0.0
    p_B_core = 0.0
    prob_reach = 1.0
    
    # For each feature, there is a chance (1 - p_skip) to evaluate it correctly.
    # If it discriminates, we stop. Otherwise, or if skipped, we continue to the next.
    for idx in order:
        if a[idx] > b[idx]:
            p_A_core += prob_reach * (1.0 - p_skip)
            prob_reach *= p_skip
        elif b[idx] > a[idx]:
            p_B_core += prob_reach * (1.0 - p_skip)
            prob_reach *= p_skip
            
    # If all features are skipped or none discriminate, guess randomly
    p_A_core += prob_reach * 0.5
    p_B_core += prob_reach * 0.5
    
    p_core = np.array([p_A_core, p_B_core])
    
    # Apply general response lapse
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 7: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 8: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Rationale:** This design dissociates standard Take-The-Best (TTB) from Stochastic Take-The-Best (Search Error). Standard TTB deterministically stops at the first discriminating feature, meaning it will always choose the option favored by the highest-validity discriminating feature (subject only to a uniform lapse rate). Stochastic TTB, however, assumes a probability 'p_skip' of missing a discriminating feature and continuing the search. By pitting a single high-validity feature favoring Option A against multiple lower-validity features favoring Option B, Stochastic TTB predicts a systematic, graded probability of choosing Option B (when the top feature is skipped), whereas standard TTB predicts Option B is only chosen via random lapses. By varying how many top features favor Option A before the lower features favor Option B, we can observe the exponential decay of errors predicted by the Stochastic TTB model.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
In the standard TTB model, the first discriminating feature always determines the choice (subject only to a uniform lapse rate). Since Option A is favored by the highest-validity discriminating feature across all trials in this design, standard TTB predicts the exact same probability of choosing Option B across all trials (P(B) = epsilon / 2), making the difference between any two sets of trials zero. In contrast, Stochastic TTB predicts that search can probabilistically skip features. Thus, trials where Option A is backed by only one early feature (Group 1) will result in a higher probability of eventually reaching features that favor Option B, compared to trials where Option A is backed by two early features (Group 2). The difference in the proportion of Option B choices between these two groups will be near zero for standard TTB and strictly positive for Stochastic TTB.

Source:
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Group 1: Trials where Option A is favored by exactly one early discriminating feature
    group1 = ['10000', '01000', '00100']
    
    # Group 2: Trials where Option A is favored by two early discriminating features
    group2 = ['11000', '10100', '10010', '01100']
    
    m1 = data[data['A_str'].isin(group1)]['response'].mean()
    m2 = data[data['A_str'].isin(group2)]['response'].mean()
    
    if pd.isna(m1) or pd.isna(m2):
        return 0.0
        
    return float(m1 - m2)

### RESULTS
- Predicted under pi_3 (simulated): -0.0153 (var=0.0074)
- Predicted under pi_4 (simulated): 0.0650 (var=0.0104)
- Observed on real data: 0.0203 (var=0.0087)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=7):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 5: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  trial 6: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 7: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Rationale:** To quantitatively dissociate Stochastic Take-The-Best (Search Error) from standard Take-The-Best (TTB), we exploit the fact that standard TTB's predictions depend exclusively on the single highest-validity discriminating feature. Any features below it are entirely ignored. In contrast, Stochastic TTB assumes a probability 'p_skip' of missing a discriminating feature and continuing the search. By systematically increasing the number of lower-validity features that favor Option B while keeping the top discriminating feature favoring Option A, standard TTB predicts a constant, high probability of choosing Option A across all conditions. Stochastic TTB, however, predicts that as the number of 'backup' features favoring Option B increases, the probability of choosing Option B will systematically rise, because there are more opportunities for the search process to land on a feature favoring B after skipping the initial feature favoring A.

**Computed schedule:** 7 unique pairs × 13 reps = 91 trials per subject.



### METRIC
Rationale:
To overcome the high between-subject variance caused by the uniformly distributed 'p_skip' parameter in Stochastic TTB, this metric binarizes the within-subject difference. Under standard TTB, the difference in Option B choices between trials with many vs. few Option B features is pure noise (driven by epsilon lapses), centered at 0. Thus, a strictly positive difference occurs less than half the time (often exactly 0 when epsilon is low). Under Stochastic TTB, any p_skip > 0 systematically increases Option B choices when more fallback features are available, making the difference reliably positive. Binarizing the effect bounds the metric's variance while preserving a large mean gap between the theories.

Source:
def metric(data: pd.DataFrame) -> float:
    b_sum = data['option_b_ratings'].apply(sum)
    high_b = data[b_sum >= 3]['response'].mean()
    low_b = data[b_sum <= 1]['response'].mean()
    
    if pd.isna(high_b) or pd.isna(low_b):
        return 0.0
        
    return 1.0 if (high_b - low_b) > 0 else 0.0

### RESULTS
- Predicted under pi_3 (simulated): 0.0000 (var=0.2484)
- Predicted under pi_4 (simulated): 1.0000 (var=0.2016)
- Observed on real data: 1.0000 (var=0.2496)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.95, 0.9, 0.85, 0.6, 0.55, 0.5])
    
    agreements = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        a_wadd = np.sum(a * validities)
        b_wadd = np.sum(b * validities)
        
        # Check if both models have strict preferences
        if a_wins != b_wins and a_wadd != b_wadd:
            tally_pref = 0 if a_wins > b_wins else 1
            wadd_pref = 0 if a_wadd > b_wadd else 1
            
            # Focus only on trials where Tallying and WADD disagree
            if tally_pref != wadd_pref:
                agreements.append(1.0 if row['response'] == tally_pref else 0.0)
                
    if len(agreements) == 0:
        return 0.5
    return float(np.mean(agreements))
```

**Observed (real) value:** 0.3133 (var=0.0068)
**Predicted under pi_3:** 0.2700 (var=0.0226)
**Predicted under pi_4:** 0.1904 (var=0.0091)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Extract option A as a 2D array
    A = np.vstack(data['option_a_ratings'].values)
    
    # Identify Trial 1: A = [0, 0, 1, 1, 1, 0]
    # WADD prefers B (response 1), Tallying prefers A (response 0)
    is_t1 = (A[:, 0] == 0) & (A[:, 1] == 0) & (A[:, 2] == 1) & (A[:, 3] == 1)
    
    # Identify Trial 3: A = [1, 1, 0, 0, 0, 0]
    # WADD prefers A (response 0), Tallying prefers B (response 1)
    is_t3 = (A[:, 0] == 1) & (A[:, 1] == 1) & (A[:, 2] == 0) & (A[:, 3] == 0)
    
    responses = data['response'].values
    
    wadd_match = 0
    total = 0
    
    wadd_match += np.sum(responses[is_t1] == 1)
    total += np.sum(is_t1)
    
    wadd_match += np.sum(responses[is_t3] == 0)
    total += np.sum(is_t3)
    
    return float(wadd_match / total) if total > 0 else 0.5

```

**Observed (real) value:** 0.7188 (var=0.0044)
**Predicted under pi_3:** 0.7688 (var=0.0284)
**Predicted under pi_4:** 0.8300 (var=0.0112)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # The experimental design guarantees that Option A always wins on the highest-validity discriminating feature.
    # TTB will therefore consistently choose Option A (response = 0).
    # Option B always has more lower-validity features whose sum outweighs Option A's single advantage.
    # WADD will therefore consistently choose Option B (response = 1).
    # The mean of the response column perfectly separates the two models: TTB is near 0, WADD is near 1.
    return float(data['response'].mean())
```

**Observed (real) value:** 0.3167 (var=0.0037)
**Predicted under pi_3:** 0.2602 (var=0.0220)
**Predicted under pi_4:** 0.3046 (var=0.0123)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float(data['response'].mean())
```

**Observed (real) value:** 0.3229 (var=0.0034)
**Predicted under pi_3:** 0.2858 (var=0.0237)
**Predicted under pi_4:** 0.3031 (var=0.0136)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, neither pure Take-The-Best (THEORY 1) nor Stochastic Take-The-Best (THEORY 2) fully capture the nuances of the observed data, although Stochastic TTB correctly predicts the ordinal sensitivity to the number of fallback features in Experiment 2. However, Experiments 5 and 6 show that the mean probability of choosing Option B (when A is favored by the top feature but B is favored by multiple lower features) is around 0.31 to 0.32. This intermediate value is poorly fit by pure TTB (which predicts values near 0, driven only by lapses) and is not perfectly captured by the search error in Stochastic TTB, which struggles with Experiments 3 and 4. The observed ~30% choice rate for Option B strongly suggests a mixture of strategies across the population or within subjects\u2014specifically, a mixture where individuals use a non-compensatory strategy (TTB) most of the time, but occasionally use a compensatory strategy (like Weighted Additive, WADD) that integrates all features.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Strategy Selection' or 'Mixture Model' theory. This theory should posit that decision-makers choose between a non-compensatory heuristic (Take-The-Best) and a compensatory strategy (Weighted Additive Model) on a trial-by-trial basis (or that the population is a mixture of TTB and WADD users). The model should have a parameter 'p_wadd' representing the probability of using the WADD strategy, and '(1 - p_wadd)' for TTB, along with a standard lapse rate. This will naturally explain the ~0.31 response rate in Experiments 5/6 and the sensitivity to lower-validity features in Experiment 2, outperforming both pure TTB and stochastic-skip TTB."
}
```

## Usage

```json
{
  "prompt_token_count": 6280,
  "candidates_token_count": 419,
  "total_token_count": 7730
}
```
