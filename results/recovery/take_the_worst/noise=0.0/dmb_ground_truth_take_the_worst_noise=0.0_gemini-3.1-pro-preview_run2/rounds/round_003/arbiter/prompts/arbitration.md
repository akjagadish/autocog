# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_4" and "pi_5") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_4" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_5" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_4
Skeptical Tallying: Decision-makers primarily rely on a Tallying heuristic, counting the number of features where one option strictly dominates the other. However, when the tallies are tied (or closely matched), they do not simply guess. Instead, they exhibit skepticism toward the highest-validity cues—perhaps viewing them as redundant, overly salient, or manipulated—and systematically break ties by favoring options that possess more lower-validity features. This is modeled by augmenting the tally score with a secondary component that weights features inversely to their stated validity.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Skeptical Tallying expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    
    # Primary mechanism: Tallying (count of strict feature-wise wins)
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Secondary mechanism: Tie-breaking favoring lower-validity features
    # Features are weighted by (1 - validity) so that lower validity cues provide a larger bonus.
    tie_breaker_a = np.sum(a * (1.0 - val))
    tie_breaker_b = np.sum(b * (1.0 - val))
    
    # Combine tally with the tie-breaker.
    # gamma controls the strength of the tie-breaker relative to a strict tally win.
    score_a = a_wins + gamma * tie_breaker_a
    score_b = b_wins + gamma * tie_breaker_b
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_5
Anti-Expertise Tallying: Decision-makers actively distrust or ignore high-validity 'expert' cues, perceiving them as overly salient, redundant, or manipulative. Instead of using them, subjects filter out features whose stated validity exceeds a certain personal threshold. After discarding these high-validity cues, subjects apply a standard Tallying heuristic (counting strict feature-wise wins) on the remaining lower-validity features to make their choice.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Anti-Expertise Tallying expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    threshold = float(parameters["threshold"])
    
    # Filter out features with validity above the threshold
    mask = val <= threshold
    
    # Fallback to all features if the threshold is so low that all features are discarded
    if not np.any(mask):
        mask = np.ones_like(val, dtype=bool)
        
    a_masked = a[mask]
    b_masked = b[mask]
    
    # Tallying on the remaining features
    a_wins = float(np.sum(a_masked > b_masked))
    b_wins = float(np.sum(b_masked > a_masked))
    
    scores = np.array([a_wins, b_wins])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 3: A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 4: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 5: A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 6: A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]

**Rationale:** This design dissociates 'Skeptical Tallying' from 'Anti-Expertise Tallying' by contrasting their mechanisms for handling high-validity cues. Skeptical Tallying retains all features in its primary tally but uses low-validity features as a tie-breaker bonus, meaning it will still strongly favor an option with a clear majority of high-validity wins. Conversely, Anti-Expertise Tallying applies a hard threshold, completely discarding features whose validities are deemed too high. By pitting an option with multiple high-validity wins against an option with fewer but lower-validity wins, Skeptical Tallying predicts a choice for the high-validity majority, while Anti-Expertise Tallying (depending on the threshold) will either predict a tie or a win for the low-validity option because the high-validity features have been filtered out.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Calculates the proportion of trials where the subject's choice aligns with the overall Tallying winner (the option with the most strictly winning features). Skeptical Tallying uses the overall tally as its primary mechanism, so it will consistently predict the overall tally winner. Anti-Expertise Tallying, however, drops high-validity features. In this specific experimental design, dropping the top two highest-validity features completely reverses the tally winner in half of the trials (Trials 3, 5, and 6). Because the threshold for Anti-Expertise Tallying frequently falls below the top validities, its simulated data will show a substantially lower rate of agreement with the overall tally winner compared to Skeptical Tallying.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    valid = a_wins != b_wins
    if not np.any(valid):
        return 0.5
        
    tally_winner = (b_wins > a_wins).astype(int)
    responses = data['response'].values
    
    match = (responses[valid] == tally_winner[valid])
    return float(np.mean(match))

### RESULTS
- Predicted under pi_4 (simulated): 0.8577 (var=0.0069)
- Predicted under pi_5 (simulated): 0.6217 (var=0.0274)
- Observed on real data: 0.6029 (var=0.0041)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=5):**
  trial 1: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  trial 5: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Rationale:** This design systematically dissociates 'Anti-Expertise Tallying' from 'Skeptical Tallying'. Skeptical Tallying always counts all features but uses low-validity features as a tie-breaker, so it strongly favors options with a strict majority of feature wins (even if they are high-validity) and breaks ties in favor of options with more low-validity features. Anti-Expertise Tallying, however, applies a hard threshold to filter out high-validity features altogether before tallying. The trials include 'opposition' trials where Option A wins on a majority of features that happen to be high-validity, causing Skeptical Tallying to choose A, while Anti-Expertise Tallying drops those features and chooses B. We also include 'tie' trials where both options have an equal number of wins, but the distribution of validities causes Skeptical Tallying's tie-breaker to favor Option A, whereas Anti-Expertise Tallying's filtering mechanism causes it to favor Option B.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times Option B is chosen in Trials 1 and 4. In these trials, Option A has a strict tallying advantage (winning on more features), meaning Skeptical Tallying will consistently select Option A. However, Option A's advantages are concentrated entirely on the highest-validity features. Anti-Expertise Tallying, which filters out high-validity features, will ignore Option A's advantages and focus on the lower-validity features where Option B wins, leading it to choose Option B significantly more often.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    def is_target_trial(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        # Trial 1
        if a == (1, 1, 1, 0, 0) and b == (0, 0, 0, 1, 1):
            return True
        # Trial 4
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 0, 0):
            return True
        return False
        
    mask = data.apply(is_target_trial, axis=1)
    if mask.sum() == 0:
        return 0.0
        
    return float(data.loc[mask, 'response'].mean())

### RESULTS
- Predicted under pi_4 (simulated): 0.1495 (var=0.0056)
- Predicted under pi_5 (simulated): 0.5689 (var=0.0759)
- Observed on real data: 0.7716 (var=0.0184)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def get_ttb_pred(a, b):
        for val_a, val_b in zip(a, b):
            if val_a > val_b:
                return 0
            if val_b > val_a:
                return 1
        return -1

    preds = [get_ttb_pred(a, b) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    
    matches = sum(1 for p, r in zip(preds, data['response']) if p == r)
    valid = sum(1 for p in preds if p != -1)
    
    return float(matches) / valid if valid > 0 else 0.0
```

**Observed (real) value:** 0.1564 (var=0.0079)
**Predicted under pi_4:** 0.1758 (var=0.0092)
**Predicted under pi_5:** 0.2147 (var=0.0067)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    mask = a_wins != b_wins
    if not np.any(mask):
        return 0.5
        
    tally_preds = np.where(a_wins > b_wins, 0, 1)
    actual_responses = data['response'].values
    
    matches = (tally_preds[mask] == actual_responses[mask])
    return float(np.mean(matches))
```

**Observed (real) value:** 0.8943 (var=0.0064)
**Predicted under pi_4:** 0.8652 (var=0.0101)
**Predicted under pi_5:** 0.8074 (var=0.0096)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    wadd_aligned = []
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        sum_a = np.sum(a)
        sum_b = np.sum(b)
        
        # Focus only on "tie" trials where Tallying predicts 50/50
        if sum_a == sum_b:
            val_a = np.sum(a * validities)
            val_b = np.sum(b * validities)
            
            if val_a > val_b:
                wadd_pref = 0
            elif val_b > val_a:
                wadd_pref = 1
            else:
                continue
                
            wadd_aligned.append(1 if row['response'] == wadd_pref else 0)
            
    if not wadd_aligned:
        return 0.5
        
    return float(np.mean(wadd_aligned))
```

**Observed (real) value:** 0.1450 (var=0.0093)
**Predicted under pi_4:** 0.3325 (var=0.0202)
**Predicted under pi_5:** 0.2562 (var=0.0321)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    val = np.array([0.99, 0.95, 0.55, 0.52, 0.5])
    
    wadd_acc = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        score_a = np.sum(val * a)
        score_b = np.sum(val * b)
        
        wadd_prefers_a = (score_a > score_b)
        wadd_prefers_b = (score_b > score_a)
        
        tally_prefers_a = (a_wins > b_wins)
        tally_prefers_b = (b_wins > a_wins)
        
        # Filter for trials where Tallying does NOT agree with WADD
        # (i.e. Tallying is tied, or Tallying actively prefers the opposite)
        if (wadd_prefers_a and not tally_prefers_a) or \
           (wadd_prefers_b and not tally_prefers_b):
            
            if wadd_prefers_a:
                wadd_correct = (row['response'] == 0)
            else:
                wadd_correct = (row['response'] == 1)
                
            wadd_acc.append(float(wadd_correct))
            
    if len(wadd_acc) == 0:
        return 0.5
    return float(np.mean(wadd_acc))
```

**Observed (real) value:** 0.1250 (var=0.0083)
**Predicted under pi_4:** 0.2131 (var=0.0166)
**Predicted under pi_5:** 0.1689 (var=0.0131)

### Experiment 7
**Design**
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Return the proportion of trials where the subject chose Option A (response == 0)
    return float((data['response'] == 0).mean())

```

**Observed (real) value:** 0.8817 (var=0.0046)
**Predicted under pi_4:** 0.6873 (var=0.0154)
**Predicted under pi_5:** 0.7096 (var=0.0215)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Calculate sum of ratings for A and B
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Filter for tie trials where both options have the same number of positive features
    tie_trials = data[sum_a == sum_b]
    
    if len(tie_trials) == 0:
        return 0.5
        
    return float(tie_trials['response'].mean())
```

**Observed (real) value:** 0.6781 (var=0.0038)
**Predicted under pi_4:** 0.7891 (var=0.0184)
**Predicted under pi_5:** 0.8137 (var=0.0238)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, Theory 2 (Anti-Expertise Tallying) significantly outperforms Theory 1 (Skeptical Tallying) in capturing the observed data, particularly in Experiments 1, 2, and 7. In Experiment 7, subjects choose the option with low-validity features over the option with high-validity features 88% of the time. In Experiment 2, subjects overwhelmingly choose Option B (77% of the time) when Option A has high-validity features and Option B has low-validity features. Theory 1, which uses tallying as the primary mechanism and inverse-validity only as a tie-breaker, completely fails to capture this (predicting 14%). Theory 2 captures the direction by filtering out high-validity features, but still underpredicts the magnitude of the effect (predicting 56% vs 77% in Exp 2, and 70% vs 88% in Exp 7). This suggests that subjects are not just filtering out high-validity features, but are actively weighting features inversely to their stated validity as their primary decision mechanism.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a brand-new theory called 'Inverse Validity Weighting'. The theory should state that subjects actively distrust expert ratings, treating high-validity cues as manipulative or overly salient. As their primary decision mechanism (not just a tie-breaker), they use a weighted additive model where the subjective weight of each feature is inversely proportional to its stated validity (e.g., weight = 1 - validity). This will allow the model to strongly predict choices for options with low-validity features over high-validity features, capturing the extreme magnitudes observed in Experiments 2 and 7 better than a hard threshold or a tallying-first approach."
}
```

## Usage

```json
{
  "prompt_token_count": 7737,
  "candidates_token_count": 411,
  "total_token_count": 9443
}
```
