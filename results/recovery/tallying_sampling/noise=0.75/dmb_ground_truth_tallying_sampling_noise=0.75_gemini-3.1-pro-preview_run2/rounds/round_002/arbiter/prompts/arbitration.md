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
Tallying (Equal Weighting) posits that decision-makers simply count the total number of positive features for each option, ignoring the differential validities of the cues. The option with the higher count of positive features is preferred. This represents a compensatory but highly frugal heuristic, where evidence is accumulated equally across all available cues. If the counts are equal, the decision-maker guesses. Response noise is modeled via a softmax over these counts with an independent lapse rate. To account for empirical choices that often deviate from pure tallying on conflict trials, the decision process incorporates substantial choice noise.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features)")
        
    # Tallying: count the number of positive features for each option
    scores = np.sum(stim, axis=1)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_4
Probabilistic Search Take-The-Best (PS-TTB)

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    diff = stim[0] - stim[1]
    
    validities = np.asarray(parameters['validities'], dtype=float)
    tau = float(parameters['tau'])
    epsilon = float(parameters['epsilon'])
    
    n_features = len(validities)
    n_samples = 1000
    
    # Gumbel-max trick to sample permutations without replacement
    # probabilities proportional to softmax(validities / tau)
    logits = validities / (tau + 1e-6)
    gumbels = np.random.gumbel(size=(n_samples, n_features))
    orders = np.argsort(-(logits + gumbels), axis=1)
    
    diff_sign = np.sign(diff)
    ordered_diffs = diff_sign[orders]
    
    # Find the first discriminating cue in each sampled search order
    abs_diffs = np.abs(ordered_diffs)
    first_non_zero_idx = np.argmax(abs_diffs, axis=1)
    has_non_zero = np.any(abs_diffs > 0, axis=1)
    
    first_non_zero_vals = ordered_diffs[np.arange(n_samples), first_non_zero_idx]
    
    wins_a = np.sum((first_non_zero_vals == 1) & has_non_zero)
    wins_b = np.sum((first_non_zero_vals == -1) & has_non_zero)
    
    total = wins_a + wins_b
    if total > 0:
        p = np.array([wins_a / total, wins_b / total])
    else:
        p = np.array([0.5, 0.5])
        
    return (1.0 - epsilon) * p + epsilon * (np.ones(2) / 2.0)

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
  trial 1: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 5: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 6: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 7: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 8: A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0]

**Rationale:** To quantitatively dissociate Tallying from Probabilistic Search Take-The-Best (PS-TTB), we employ a 5-feature design with a steep gradient in cue validities. Tallying simply counts the number of positive features and ignores validities, whereas PS-TTB probabilistically searches through cues weighted by their validities and decides based on the first discriminating cue. The design includes 'conflict' trials where one option has more positive features (favored by Tallying) but the competing option is favored by the highest-validity cue (favored by PS-TTB). We also include 'tie' trials where both options have the same number of positive features (Tallying predicts guessing) but the features favoring one option have much higher validities (PS-TTB strongly favors this option), providing a robust quantitative dissociation.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the overall probability that a subject chooses the option with the higher total number of positive features specifically on trials where the feature sum difference is exactly 1 (Trials 1, 5, 6, and 7). Because the parameter distribution for PS-TTB allows 'tau' to range up to 100.0, the vast majority of simulated PS-TTB subjects operate in a 'Random Search' regime. In this regime, PS-TTB predicts a choice probability exactly proportional to the number of favoring cues: 3/5 = 0.60 (before lapse rate). In contrast, Tallying uses a softmax over the sum difference, and its beta parameter distribution yields a significantly higher expected probability for a difference of 1 (average core probability ~0.72). By pooling all 48 of these trials per subject, we minimize binomial noise, creating a stable and statistically significant gap between Tallying's higher predicted accuracy and PS-TTB's lower proportional accuracy.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    A_ratings = np.stack(data['option_a_ratings'].values)
    B_ratings = np.stack(data['option_b_ratings'].values)
    
    sum_A = A_ratings.sum(axis=1)
    sum_B = B_ratings.sum(axis=1)
    
    # Identify all trials where the difference in total positive features is exactly 1.
    # These are T1, T5, T6, and T7.
    diff_1_mask = np.abs(sum_A - sum_B) == 1
    
    if not np.any(diff_1_mask):
        return 0.5
        
    data_diff1 = data[diff_1_mask]
    sum_A_diff1 = sum_A[diff_1_mask]
    sum_B_diff1 = sum_B[diff_1_mask]
    responses = data_diff1['response'].values
    
    # 1 if the subject chose the option with the higher total number of positive features, 0 otherwise
    chose_higher = np.where(sum_A_diff1 > sum_B_diff1, responses == 0, responses == 1)
    
    return float(np.mean(chose_higher))

### RESULTS
- Predicted under pi_3 (simulated): 0.6233 (var=0.0174)
- Predicted under pi_4 (simulated): 0.5617 (var=0.0039)
- Observed on real data: 0.6117 (var=0.0051)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 4: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 6: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 7: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 8: A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Rationale:** To quantitatively dissociate Probabilistic Search Take-The-Best (PS-TTB) from Tallying, we utilize a 5-feature design with a steep gradient in cue validities. Tallying decides based on the simple sum of positive features irrespective of their validities, whereas PS-TTB probabilistically searches cues weighted by their validities and decides on the first discriminating cue. We include 'conflict' trials where one option has fewer positive features but is favored by the highest-validity cues (Tallying favors the option with more features, PS-TTB favors the one with the highest-validity feature). We also include 'tie' trials where both options have an equal number of positive features (Tallying predicts guessing) but the features differ in validity (PS-TTB strongly favors the option with higher-validity features).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Through mathematical analysis, we find that for >95% of its parameter space, Probabilistic Search Take-The-Best (PS-TTB) behaves identically to Random Search Take-The-Best. In this specific design, Random Search predicts choice probabilities strictly equal to the ratio of positive features (e.g., 4 vs 1 -> P=0.8). Consequently, PS-TTB's maximum theoretical accuracy relative to the feature sum is mathematically capped at ~0.716 across all non-tie trials. In contrast, Tallying uses a logistic link function on the feature difference, which routinely produces choice probabilities > 0.90 when beta is large and epsilon is small.

Previous attempts to capture this difference using steep thresholds (e.g., a sigmoid at 0.80 with slope 30) failed because they created a highly volatile Bernoulli-like distribution for Tallying, causing its variance to explode and nullifying the t-test. To solve this, we center a much softer sigmoid at 0.75 (the midpoint between PS-TTB's ceiling and Tallying's dense right tail). This smooth transformation heavily amplifies the high-accuracy subjects uniquely produced by Tallying while keeping the variance tightly bounded, ensuring a highly robust and significant double dissociation.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate the sum of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Isolate trials where the feature sums differ (diff > 0)
    mask = sum_a != sum_b
    if not mask.any():
        return 0.5
        
    valid_data = data[mask].copy()
    
    # Determine the 'majority' option (0 for A, 1 for B)
    maj_choice = (sum_a[mask] < sum_b[mask]).astype(int)
    
    # Check if the subject chose the majority option
    valid_data['is_maj'] = (valid_data['response'] == maj_choice).astype(float)
    
    # Calculate the overall accuracy relative to the feature sum per subject
    subj_acc = valid_data.groupby('subject_id')['is_maj'].mean()
    
    # Apply a smooth sigmoid centered at 0.75.
    # Tallying uses a logistic link function, routinely producing choice accuracies > 0.80 
    # when beta is moderate/high and epsilon is low. 
    # PS-TTB with tau > 1 (99% of its parameter space) behaves identically to Random Search,
    # whose theoretical maximum accuracy on these trials is capped exactly at ~0.716.
    # A smooth slope (12.0) prevents the variance from exploding (unlike steep thresholds or high powers),
    # while cleanly separating the dense right tail of Tallying from the bounded distribution of PS-TTB.
    score = 1.0 / (1.0 + np.exp(-12.0 * (subj_acc - 0.75)))
    
    return float(score.mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.3180 (var=0.0715)
- Predicted under pi_4 (simulated): 0.1988 (var=0.0196)
- Observed on real data: 0.1432 (var=0.0027)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_0 = data['option_a_ratings'].apply(lambda x: x[0])
    b_0 = data['option_b_ratings'].apply(lambda x: x[0])
    ttb_choice = np.where(b_0 > a_0, 1, 0)
    return float(np.mean(data['response'] == ttb_choice))
```

**Observed (real) value:** 0.4550 (var=0.0021)
**Predicted under pi_3:** 0.4154 (var=0.0064)
**Predicted under pi_4:** 0.4452 (var=0.0026)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.95, 0.75, 0.65, 0.55])
    
    def is_ttb_match(row):
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # TTB prediction
        ttb_winner = None
        for i in range(4):
            if a[i] > b[i]:
                ttb_winner = 0
                break
            elif b[i] > a[i]:
                ttb_winner = 1
                break
                
        # WADD expected prediction (assuming uniform weights)
        wadd_a = np.sum(a * validities)
        wadd_b = np.sum(b * validities)
        wadd_winner = 0 if wadd_a > wadd_b else 1
        
        # Only consider compensatory trials where the models disagree
        if ttb_winner is not None and ttb_winner != wadd_winner:
            return 1.0 if row['response'] == ttb_winner else 0.0
        return np.nan

    matches = data.apply(is_ttb_match, axis=1)
    return float(matches.mean())
```

**Observed (real) value:** 0.4225 (var=0.0057)
**Predicted under pi_3:** 0.3733 (var=0.0167)
**Predicted under pi_4:** 0.3950 (var=0.0059)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    def is_11000(x):
        return tuple(x) == (1, 1, 0, 0, 0)
    
    def is_00111(x):
        return tuple(x) == (0, 0, 1, 1, 1)
        
    a_11000 = data['option_a_ratings'].apply(is_11000)
    b_00111 = data['option_b_ratings'].apply(is_00111)
    
    a_00111 = data['option_a_ratings'].apply(is_00111)
    b_11000 = data['option_b_ratings'].apply(is_11000)
    
    t1 = a_11000 & b_00111
    t3 = a_00111 & b_11000
    
    chose_11000 = (t1 & (data['response'] == 0)) | (t3 & (data['response'] == 1))
    
    relevant = t1 | t3
    if relevant.sum() == 0:
        return 0.5
    return float(chose_11000.sum() / relevant.sum())
```

**Observed (real) value:** 0.4183 (var=0.0241)
**Predicted under pi_3:** 0.3817 (var=0.0195)
**Predicted under pi_4:** 0.4542 (var=0.0118)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_target_trial(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        # Target trials where WADD and Tallying strictly disagree
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            return True
        if a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            return True
        return False

    mask = data.apply(is_target_trial, axis=1)
    target_data = data[mask]
    
    if len(target_data) == 0:
        return 0.5
        
    sum_a = target_data['option_a_ratings'].apply(sum)
    sum_b = target_data['option_b_ratings'].apply(sum)
    
    # Calculate how often the subject chose the option with MORE positive features (Tallying's preference)
    chose_more = ((target_data['response'] == 0) & (sum_a > sum_b)) | \
                 ((target_data['response'] == 1) & (sum_b > sum_a))
                 
    return float(chose_more.mean())
```

**Observed (real) value:** 0.5867 (var=0.0125)
**Predicted under pi_3:** 0.6075 (var=0.0135)
**Predicted under pi_4:** 0.5675 (var=0.0095)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, neither pure Tallying (pi_3) nor Probabilistic Search Take-The-Best (pi_4) fully captures the observed behavior, though PS-TTB generally performs better on experiments emphasizing cue validities (Exp 2, 3, 4). Tallying completely ignores cue validities, which leads to large prediction errors when validities strongly dictate choices. Conversely, PS-TTB ignores the accumulation of multiple weak cues once a single strong discriminating cue is found, which causes it to miss the mark on Exp 1 where feature counting plays a role. The observed data consistently falls somewhere between a pure non-compensatory strategy (PS-TTB) and a pure unweighted compensatory strategy (Tallying). This suggests that subjects are likely integrating all available cues but weighting them by their respective validities.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a Weighted Additive Model (WADD) to replace Tallying. In WADD, decision-makers compute a weighted sum of the features for each option, where the weights are derived from the cue validities (e.g., proportional to the validities or their log-odds). The final choice is generated via a softmax function over these weighted sums, incorporating a lapse rate for noise. This theory is fully compensatory (integrating all cues, unlike PS-TTB) but remains sensitive to the varying importance of each cue (unlike Tallying), allowing it to better explain the intermediate choice probabilities observed across the experiments."
}
```

## Usage

```json
{
  "prompt_token_count": 7003,
  "candidates_token_count": 340,
  "total_token_count": 8309
}
```
