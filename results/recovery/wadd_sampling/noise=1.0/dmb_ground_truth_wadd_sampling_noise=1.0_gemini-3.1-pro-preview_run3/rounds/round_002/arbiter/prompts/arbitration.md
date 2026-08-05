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
Conflict-Induced Guessing Theory posits that decision makers concurrently evaluate options using both a non-compensatory heuristic (Take The Best) and a compensatory heuristic (Tallying). When these two strategies agree, the decision maker confidently chooses the favored option (subject to standard softmax noise). However, when the strategies conflict—or when one strategy fails to corroborate the other (e.g., Tallying is tied while TTB prefers one option)—the decision maker experiences cognitive conflict or ambiguity. Unable to easily resolve this conflict, they resort to uniform guessing. This explains the consistent ~50% choice rates observed on adversarial trials and trials with weak corroborating evidence without requiring extreme parameter values.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    a, b = stim[0], stim[1]
    
    # Take The Best (TTB) prediction
    val = np.asarray(parameters["validities"], dtype=float)
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    ttb_winner = None
    for j in cue_order:
        if a[j] > b[j]:
            ttb_winner = 0
            break
        elif b[j] > a[j]:
            ttb_winner = 1
            break
            
    # Tallying prediction
    a_wins = np.sum(a > b)
    b_wins = np.sum(b > a)
    if a_wins > b_wins:
        tally_winner = 0
    elif b_wins > a_wins:
        tally_winner = 1
    else:
        tally_winner = None
        
    # Determine choice probabilities
    if ttb_winner != tally_winner or ttb_winner is None:
        # Conflict or lack of clear corroboration leads to guessing
        p_core = np.array([0.5, 0.5])
    else:
        # No conflict: both strategies agree
        scores = np.array([1.0, 0.0]) if ttb_winner == 0 else np.array([0.0, 1.0])
            
        beta = float(parameters["beta"])
        z = beta * (scores - scores.max())
        e = np.exp(z)
        p_core = e / e.sum()
        
    epsilon = float(parameters["epsilon"])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_3
Weighted Additive (WADD) theory posits that decision makers integrate all available information by computing a weighted sum of the features for each option. The weights correspond to the cue validities, often transformed into log-odds to represent the evidence weight of each cue. The option with the higher weighted sum is more likely to be chosen, with choices generated via a softmax function over the options' values. This compensatory mechanism allows multiple lower-validity cues to jointly outweigh or tie with a single higher-validity cue, explaining ~50% choice rates on adversarial trials where these conflicting evidence sources balance out.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    
    # Retrieve and clip validities to avoid division by zero or log(0)
    val = np.asarray(parameters["validities"], dtype=float)
    val = np.clip(val, 0.5001, 0.9999)
    
    # Compute weights as log-odds of validities
    w = np.log(val / (1.0 - val))
    
    # Compute the weighted additive scores for each option
    score_a = np.sum(a * w)
    score_b = np.sum(b * w)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Apply lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)

## EXPERIMENT 1 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.85, 0.8, 0.75, 0.6, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 4: A=[1, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 7: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 8: A=[1, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]

**Rationale:** To quantitatively dissociate Conflict-Induced Guessing Theory from Weighted Additive (WADD) theory, we use a 5-feature design with validities [0.85, 0.80, 0.75, 0.60, 0.55]. Conflict-Induced Guessing Theory posits that decision makers use both Take The Best (TTB) and Tallying concurrently; if they agree, the subject chooses confidently, but if they conflict or one ties, the subject guesses (~50%). WADD posits a continuous integration of log-odds weights. We design specific trials to contrast these. In Trial 1, Option A is favored by both TTB (highest validity cue) and Tallying (3 cues to 2), so Conflict Theory predicts a confident choice for A. However, Option B's two cues have a higher combined log-odds weight than A's three cues, so WADD predicts a confident choice for B. In Trial 2, TTB favors A while Tallying favors B; Conflict Theory predicts ~50% guessing, whereas WADD strongly prefers A. Additional trials systematically vary these alignments to ensure robust dissociation across the full parameter space of both models.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Calculates the difference in the probability of choosing Option B between Trial 5 and Trial 1. On Trial 1, Conflict Theory predicts a confident choice for A (since TTB and Tallying agree), while WADD predicts a confident choice for B (since the sum of log-odds for B's cues outweighs A's). On Trial 5, the options are swapped, so Conflict Theory predicts B and WADD predicts A. Thus, this metric should yield ~1.0 for Conflict Theory and ~-1.0 for WADD, providing a maximum separation with minimal within-subject variance.

Source:
def metric(data: pd.DataFrame) -> float:
    a_tuples = data['option_a_ratings'].apply(tuple)
    b_tuples = data['option_b_ratings'].apply(tuple)
    
    t1_mask = (a_tuples == (1, 0, 0, 1, 1)) & (b_tuples == (0, 1, 1, 0, 0))
    t5_mask = (a_tuples == (0, 1, 1, 0, 0)) & (b_tuples == (1, 0, 0, 1, 1))
    
    resp_t1 = data.loc[t1_mask, 'response'].mean()
    resp_t5 = data.loc[t5_mask, 'response'].mean()
    
    val_t1 = float(resp_t1) if not pd.isna(resp_t1) else 0.5
    val_t5 = float(resp_t5) if not pd.isna(resp_t5) else 0.5
    
    return val_t5 - val_t1

### RESULTS
- Predicted under pi_4 (simulated): 0.7133 (var=0.0273)
- Predicted under pi_3 (simulated): -0.2583 (var=0.0742)
- Observed on real data: -0.0133 (var=0.0243)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.88, 0.82, 0.75, 0.65, 0.55]

**Trial pairs (n=5):**
  trial 1: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 4: A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 5: A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]

**Rationale:** To quantitatively dissociate Weighted Additive (WADD) theory from Conflict-Induced Guessing Theory, we use a 5-feature design with validities set to [0.88, 0.82, 0.75, 0.65, 0.55]. Conflict-Induced Guessing Theory predicts that when Take The Best (TTB) and Tallying conflict or tie, subjects will experience ambiguity and guess (~50%). In contrast, WADD integrates all features using log-odds weights (approximately 1.99, 1.52, 1.10, 0.62, and 0.20) and makes directional choices based on the weighted sum. We designed trials where TTB and Tallying conflict (e.g., TTB prefers one option, Tallying prefers the other) or one heuristic ties, leading Conflict Theory to predict guessing. Meanwhile, WADD's log-odds weights heavily favor one option, leading to confident directional predictions, thereby strongly dissociating the two theories.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
Focuses on two specific trials where the theories make highly divergent predictions. In Trial 1 (A=[0,1,1,1,0] vs B=[1,0,0,0,1]), WADD strongly favors A due to the combined weight of cues 2, 3, and 4, whereas Conflict Theory predicts 50% guessing because TTB favors B and Tallying favors A. In Trial 2 (A=[1,0,0,0,0] vs B=[0,1,1,0,0]), WADD strongly favors B, while Conflict Theory again predicts guessing. The metric computes the average rate of choosing the WADD-favored option across these two trials, leading to a high value (~0.85+) for WADD and ~0.5 for Conflict Theory.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    a_tuples = data['option_a_ratings'].apply(tuple)
    
    mask_t1 = (a_tuples == (0, 1, 1, 1, 0))
    mask_t2 = (a_tuples == (1, 0, 0, 0, 0))
    
    data_t1 = data[mask_t1]
    data_t2 = data[mask_t2]
    
    val1 = (data_t1['response'] == 0).mean() if len(data_t1) > 0 else 0.5
    val2 = (data_t2['response'] == 1).mean() if len(data_t2) > 0 else 0.5
    
    return float((val1 + val2) / 2.0)

### RESULTS
- Predicted under pi_4 (simulated): 0.5147 (var=0.0057)
- Predicted under pi_3 (simulated): 0.8095 (var=0.0144)
- Observed on real data: 0.4916 (var=0.0085)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        winner = None
        for i in range(len(a)):
            if a[i] > b[i]:
                winner = 0
                break
            elif b[i] > a[i]:
                winner = 1
                break
        if winner is not None:
            matches.append(1 if resp == winner else 0)
    return float(np.mean(matches)) if matches else 0.5
```

**Observed (real) value:** 0.4900 (var=0.0012)
**Predicted under pi_4:** 0.5360 (var=0.0025)
**Predicted under pi_3:** 0.6058 (var=0.0018)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float(data['response'].mean())
```

**Observed (real) value:** 0.4981 (var=0.0023)
**Predicted under pi_4:** 0.4918 (var=0.0024)
**Predicted under pi_3:** 0.4067 (var=0.0021)

### Experiment 5
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    ttb_aligned = 0
    total = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_pred = None
        for i in range(4):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred is not None:
            if resp == ttb_pred:
                ttb_aligned += 1
            total += 1
            
    return ttb_aligned / total if total > 0 else 0.5
```

**Observed (real) value:** 0.5033 (var=0.0016)
**Predicted under pi_4:** 0.4969 (var=0.0038)
**Predicted under pi_3:** 0.2437 (var=0.0109)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float(data['response'].mean())
```

**Observed (real) value:** 0.5054 (var=0.0018)
**Predicted under pi_4:** 0.5098 (var=0.0029)
**Predicted under pi_3:** 0.7238 (var=0.0085)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across almost all experiments (2 through 6), the observed metrics tightly cluster around 0.50, indicating that subjects are essentially guessing or that their aggregate choices cancel out to 50/50. Theory 1 (Conflict-Induced Guessing) captures this well for Exps 2-6 by predicting guessing when heuristics conflict. However, Theory 1 fails dramatically on Experiment 1, predicting a strong effect (~0.71) where the observed data shows none (~-0.01). In Exp 1, both TTB and Tallying agree, yet subjects still appear to guess. Theory 2 (WADD) fails broadly across the board because it consistently predicts directional preferences (due to log-odds integration) that do not materialize in the data. The persistent ~0.50 observed across all tasks\u2014even when simple heuristics align\u2014suggests a different underlying mechanism, such as strict random guessing due to cognitive overload, or a threshold-based tallying where a difference of only 1 cue is insufficient to drive a confident choice.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace WADD (Theory 2) with a 'Threshold Tallying Theory' or a 'Cognitive Overload / Random Guessing Theory'. The new theory should posit that subjects only make a directional choice if the unweighted sum of features (Tallying) heavily favors one option (e.g., a difference of >= 2 features). If the difference is 0 or 1, the evidence is deemed too weak or ambiguous, resulting in uniform guessing. This would perfectly explain the ~0.50 choice rates across almost all adversarial and aligned trials seen so far, including the failure case of Theory 1 in Experiment 1 (where the tally difference was only 1)."
}
```

## Usage

```json
{
  "prompt_token_count": 5996,
  "candidates_token_count": 397,
  "total_token_count": 8026
}
```
