# Round 2 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_4` — SURVIVED ✓

**Description:** Strategy Mixture Theory (TTB + WADD): Decision makers do not universally adopt a single monolithic strategy. Instead, choices are generated from a probabilistic mixture of decision rules. On any given trial, an individual uses a non-compensatory heuristic (Take The Best) with probability 'alpha', and a compensatory strategy (Weighted Additive - WADD) with probability '1 - alpha'. Mixing these strategies captures intermediate rates of compensatory and non-compensatory choices, while WADD leverages cue validities for a more nuanced compensatory evaluation.

**Rationale:** Following the critic's advice, I shifted the `alpha` parameter range from [0.0, 1.0] to [0.5, 1.0] to reflect the strong empirical bias toward non-compensatory choices (TTB-like behavior) observed in the data. I also increased the lower bound of `beta` from 0.1 to 1.0 to reduce baseline noise in the softmax functions and prevent the choice probabilities from flattening too much toward 0.5.

**Parameters:**
  - `alpha`: `[0.5, 1.0]`
  - `beta`: `[1.0, 20.0]`
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
    val = np.asarray(parameters["validities"], dtype=float)
    
    beta = float(parameters["beta"])
    alpha = float(parameters["alpha"])
    epsilon = float(parameters["epsilon"])
    
    # Strategy 1: Take The Best (TTB)
    cue_order = np.argsort(-val, kind="stable").tolist()
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        p_ttb = np.array([0.5, 0.5])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        z_ttb = beta * (scores_ttb - scores_ttb.max())
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / e_ttb.sum()
        
    # Strategy 2: WADD (Weighted Additive)
    score_a_wadd = np.sum(a * val)
    score_b_wadd = np.sum(b * val)
    scores_wadd = np.array([score_a_wadd, score_b_wadd])
    
    z_wadd = beta * (scores_wadd - scores_wadd.max())
    e_wadd = np.exp(z_wadd)
    p_wadd = e_wadd / e_wadd.sum()
    
    # Mixture of the two strategies
    p_mix = alpha * p_ttb + (1.0 - alpha) * p_wadd
    
    # Apply lapse rate
    n_opts = p_mix.shape[0]
    p_final = (1.0 - epsilon) * p_mix + epsilon * (np.ones(n_opts) / n_opts)
    
    return p_final
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


### slot 2 — `pi_3` — KILLED ✗

**Description:** The Weighted Additive (WADD) model with non-linear weight scaling posits that decision makers integrate all available information by computing a weighted sum of features. However, the weighting of cues is not strictly proportional to their log-odds validity. Instead, decision makers apply a non-linear transformation (parameterized by gamma) to the log-odds, allowing them to stretch the weight differential. This permits WADD to approximate lexicographic (TTB-like) choice when gamma > 1, or more uniform (Tallying-like) weighting when gamma < 1, while remaining a fully compensatory integration process.

**Rationale:** Following the critic's advice, we constrained the upper bounds of both `gamma` and `beta`. The previous `gamma` range up to 5.0 allowed the weights to stretch so much that the model over-predicted TTB consistency in Experiment 1. By restricting `gamma` to [0.5, 2.5] and `beta` to [0.1, 10.0], the model is prevented from collapsing into an overly deterministic lexicographic strategy, softening the predictions to better match the empirical mixture of compensatory and non-compensatory behaviors.

**Parameters:**
  - `beta`: `[0.1, 10.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `gamma`: `[0.5, 2.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Transform validities to log-odds weights, clipping to avoid infinity
    val_clipped = np.clip(val, 0.5001, 0.9999)
    log_odds = np.log(val_clipped / (1.0 - val_clipped))
    
    gamma = float(parameters["gamma"])
    w = np.sign(log_odds) * (np.abs(log_odds) ** gamma)
    
    # Compute weighted sum for each option
    score_a = np.sum(w * a)
    score_b = np.sum(w * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the weighted scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## Replacement

### `pi_5` → slot 2 (via `new_theory`)

**Description:** Cue Difference Threshold Theory: Decision-makers evaluate options lexicographically but demand that the best discriminating cue provides a decisive advantage. A cue is deemed decisive if its validity exceeds the best opposing cue by a sufficient threshold, or if the sheer number of opposing cues is small enough (below a tallying deficit limit). If the top cue's advantage is challenged by a concentrated block of moderately high opposing cues (failing both conditions), the decision-maker abandons the non-compensatory heuristic and falls back to a compensatory Weighted Additive (WADD) process to resolve the choice.

**Rationale:** Reverting to the exact hard-gating mechanism from the accepted Iteration 1 base, which performed best so far. We retain the WADD fallback and boolean switch (cue difference decisive OR deficit OK). To give the optimizer more flexibility to fit the hard thresholds without breaking the mechanism family, the parameter ranges for `beta` and `threshold` are widened, while preserving the random lapse rate (`epsilon`) at the end of the calculation.

**Parameters:**
  - `threshold`: `[0.0, 1.0]`
  - `deficit_limit`: `{0, 1, 2, 3, 4, 5}`
  - `beta`: `[0.1, 25.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    threshold = float(parameters["threshold"])
    deficit_limit = int(parameters["deficit_limit"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Identify which cues favor which option
    favor_a = (a > b)
    favor_b = (b > a)
    
    max_val_a = np.max(val[favor_a]) if np.any(favor_a) else 0.0
    max_val_b = np.max(val[favor_b]) if np.any(favor_b) else 0.0
    
    winner_ttb = 0 if max_val_a > max_val_b else (1 if max_val_b > max_val_a else None)
    
    if winner_ttb is not None:
        # Number of cues favoring the TTB loser
        num_opposing = np.sum(favor_b) if winner_ttb == 0 else np.sum(favor_a)
        
        # Two conditions for TTB to be considered decisive:
        # 1. The validity difference between the best cues of each option is large enough.
        # 2. The number of opposing cues is within the acceptable deficit limit.
        cue_diff_decisive = abs(max_val_a - max_val_b) >= threshold
        deficit_ok = num_opposing <= deficit_limit
        
        if cue_diff_decisive or deficit_ok:
            # Decisive advantage: stick to TTB
            scores = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        else:
            # Not decisive: fall back to compensatory WADD
            val_clipped = np.clip(val, 0.5001, 0.9999)
            log_odds = np.log(val_clipped / (1.0 - val_clipped))
            score_a = np.sum(log_odds * a)
            score_b = np.sum(log_odds * b)
            
            # Normalize compensatory scores by total weight to keep the scale 
            # comparable to the [0, 1] TTB scores for the softmax temperature.
            total_w = np.sum(log_odds)
            scores = np.array([score_a, score_b]) / total_w if total_w > 0 else np.array([0.5, 0.5])
    else:
        scores = np.array([0.5, 0.5])
        
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    p_final = (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
    
    return p_final
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```
