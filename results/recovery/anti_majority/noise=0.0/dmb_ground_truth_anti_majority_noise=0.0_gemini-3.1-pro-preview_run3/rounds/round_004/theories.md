# Round 4 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_4` — SURVIVED ✓

**Description:** Strategy Mixture (TTB + Tallying): Decision makers do not universally adhere to a single strategy. Instead, they use a probabilistic mixture of a non-compensatory strategy (Take The Best) and a compensatory strategy (Tallying). A parameter P_TTB dictates the probability of using TTB on any given trial, while 1 - P_TTB is the probability of using Tallying. This accounts for intermediate levels of TTB-consistency and Tallying-consistency observed in empirical data across subjects and trials. The mixture captures a balance between TTB and Tallying, avoiding over-reliance on uniform guessing.

**Rationale:** Following the critic's advice, the minimal edit adjusts the `p_ttb` range to `[0.35, 0.95]` to perfectly split the difference between the previous two iterations. This should balance the slight over- and under-predictions of TTB consistency across the four experiments while keeping epsilon noise low.

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `p_ttb`: `[0.35, 0.95]`
  - `epsilon`: `[0.0, 0.2]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np

    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    n_features = len(a)
    
    val = np.asarray(parameters["validities"], dtype=float)
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    # Take The Best (TTB) Strategy
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb == 0:
        scores_ttb = np.array([1.0, 0.0])
    elif winner_ttb == 1:
        scores_ttb = np.array([0.0, 1.0])
    else:
        scores_ttb = np.array([0.0, 0.0])
        
    # Tallying Strategy
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    # Normalize by n_features to keep scale comparable to TTB for the shared beta
    scores_tally = np.array([a_wins, b_wins]) / max(1.0, float(n_features))
    
    beta = float(parameters["beta"])
    
    # TTB Probabilities
    z_ttb = beta * (scores_ttb - scores_ttb.max())
    e_ttb = np.exp(z_ttb)
    p_ttb_dist = e_ttb / e_ttb.sum()
    
    # Tallying Probabilities
    z_tally = beta * (scores_tally - scores_tally.max())
    e_tally = np.exp(z_tally)
    p_tally_dist = e_tally / e_tally.sum()
    
    # Mixture
    p_ttb_weight = float(parameters["p_ttb"])
    epsilon = float(parameters["epsilon"])
    
    p_core = p_ttb_weight * p_ttb_dist + (1.0 - p_ttb_weight) * p_tally_dist
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


### slot 2 — `pi_6` — KILLED ✗

**Description:** Weighted Additive with Diminishing Returns (WADD-DR): Decision-makers integrate all available discriminating cues but apply a sub-additive (concave) transformation to the accumulated evidence. Cue validities are first scaled non-linearly to reflect subjective weighting. Then, the total accumulated evidence for each option undergoes a concave transformation before being converted to choice probabilities. This naturally accounts for the dilution effect when multiple weaker cues are added, pulling choice probabilities toward 0.5, while maintaining sensitivity to the overall balance of evidence.

**Rationale:** Constrain epsilon to [0.0, 0.1] and beta to [0.1, 10.0]. Initial logic and parameters are validated. The model previously relied on high noise to minimize aggregate error, flatlining predictions. Bypassing intermediate tuning, we directly restrict the noise bounds. Standard processing applied. This enforces structural reliance on the WADD-DR mechanism.

**Parameters:**
  - `gamma`: `[0.1, 30.0]`
  - `alpha`: `[0.01, 1.0]`
  - `beta`: `[0.1, 10.0]`
  - `epsilon`: `[0.0, 0.1]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    alpha = float(parameters["alpha"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Scale validities: subtract 0.5 so a random cue provides 0 evidence, then apply non-linear scaling
    w = np.maximum(0.0, val - 0.5) ** gamma
    
    # Accumulate evidence for each option based on discriminating cues
    diff = a - b
    ev_a = np.sum(w[diff > 0])
    ev_b = np.sum(w[diff < 0])
    
    # Apply sub-additive (concave) transformation to accumulated evidence
    # alpha < 1 yields diminishing returns for additional evidence
    ev_a_trans = (ev_a + 1e-9) ** alpha
    ev_b_trans = (ev_b + 1e-9) ** alpha
    
    # Convert transformed evidence to choice probabilities via softmax
    scores = np.array([ev_a_trans, ev_b_trans])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## Replacement

### `pi_7` → slot 2 (via `new_theory`)

**Description:** Sequential Evidence Accumulation with Flexible Threshold: Decision-makers search through cues sequentially in order of their validity. As they evaluate each cue, they accumulate evidence for the favored option. The search stops as soon as the absolute difference in accumulated evidence between the two options reaches a subjective threshold. If the threshold is low (or zero), this mechanism perfectly mimics Take-The-Best by stopping at the first discriminating cue. If the threshold is high, it evaluates all available cues, naturally transitioning into compensatory strategies like Weighted Additive (WADD) or Tallying.

**Rationale:** Following the critic's advice on Iteration 5, the model was still slightly too deterministic, yielding sharp step-function probabilities that overpredicted Take-The-Best agreement in Experiment 3 and overestimated the metric in Experiment 8. To soften this deterministic edge without altering the core Sequential Evidence Accumulation stopping behavior, we reduce the upper bound of the softmax inverse temperature `beta` from 20.0 to 5.0. This prevents extreme scaling of evidence differences, naturally pulling extreme predictions closer to observed human baselines.

**Parameters:**
  - `gamma`: `[0.0, 3.0]`
  - `theta`: `[0.0, 1.0]`
  - `beta`: `[0.1, 5.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    theta = float(parameters["theta"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Search through cues in order of validity (highest first)
    cue_order = np.argsort(-val, kind="stable")
    
    # Scale validities non-linearly to represent subjective evidence weights
    w = val ** gamma
    
    ev_a = 0.0
    ev_b = 0.0
    
    # Sequential evidence accumulation
    for i in cue_order:
        if a[i] > b[i]:
            ev_a += w[i]
        elif b[i] > a[i]:
            ev_b += w[i]
            
        # Stop search if the evidence difference reaches the threshold
        # (and ensure we don't stop prematurely if no discriminating evidence has been found yet)
        if abs(ev_a - ev_b) >= theta and abs(ev_a - ev_b) > 0:
            break
            
    # Convert accumulated evidence into choice probabilities via softmax
    scores = np.array([ev_a, ev_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate lapse rate (guessing)
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```
