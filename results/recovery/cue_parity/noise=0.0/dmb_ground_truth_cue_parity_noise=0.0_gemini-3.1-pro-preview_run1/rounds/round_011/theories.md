# Round 11 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_13` — KILLED ✗

**Description:** Decision-makers use a purely compensatory Weighted Additive Strategy (WADD). Instead of applying early stopping or lexicographic rules, individuals evaluate all available features for both options. Each feature is weighted by a non-linear transformation of its objective validity, capturing varying sensitivities to evidence strength. The overall subjective value of an option is the sum of its weighted features, and choices are made probabilistically based on the difference in these overall values. By allowing for very large scaling parameters, the model can approximate non-compensatory behavior within a purely compensatory framework.

**Rationale:** Following the critic's feedback, we revert to the successful unnormalized chance-centered power-law WADD base from Iteration 1. To improve fit on experiments where human behavior appears lexicographic, we significantly expand the parameter ranges for `gamma` (up to 25.0) and `beta` (up to 100.0). This minimal edit allows the purely compensatory WADD model to naturally approximate non-compensatory behavior by letting the most valid cues dominate the weighted sum when `gamma` is large, without altering the core mechanism.

**Parameters:**
  - `beta`: `[0.1, 100.0]`
  - `gamma`: `[0.1, 25.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Transformation parameter for validities
    gamma = float(parameters["gamma"])
    
    # Center validities to chance level (0.5), then apply non-linear scaling
    centered_val = np.clip(val - 0.5, 1e-6, 0.5)
    weights = centered_val ** gamma
    
    # Calculate overall subjective values (weighted sums)
    scores = np.array([np.sum(a * weights), np.sum(b * weights)])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice rule with numerical stability
    z = beta * scores
    z -= np.max(z)
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
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


### slot 2 — `pi_9` — SURVIVED ✓

**Description:** Decision-makers use a Sequential Evidence Accumulation strategy with a stopping rule. They inspect features one by one in descending order of their validity, maintaining a running sum of the differences between the options. If the absolute accumulated evidence reaches or exceeds a specific threshold, they stop and make a choice based on that evidence. If the threshold is not reached, they evaluate all features and decide based on the final tally. This allows the model to smoothly transition between Take-The-Best (low threshold) and Tallying (high threshold) behaviors.

**Rationale:** Following the critic's advice, we implement a Sequential Evidence Accumulation model where features are sampled in descending order of validity. By allowing the stopping threshold to range from 0.0 to 3.0, the model can dynamically recover Take-The-Best behavior (when threshold <= 1.0, stopping after the first differentiating feature) or Tallying behavior (when threshold is high, accumulating across all features). This single unified mechanism avoids the scaling issues of the mixture model and naturally explains intermediate choice proportions observed in the experiments.

**Parameters:**
  - `threshold`: `[0.0, 3.0]`
  - `beta`: `[0.1, 15.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Order features by validity descending
    order = np.argsort(val)[::-1]
    
    threshold = float(parameters["threshold"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    diff = a - b
    accumulated_evidence = 0.0
    
    for idx in order:
        accumulated_evidence += diff[idx]
        if abs(accumulated_evidence) >= threshold and abs(accumulated_evidence) > 0:
            break
            
    scores = np.array([accumulated_evidence, -accumulated_evidence])
    
    z = beta * scores
    z -= np.max(z)
    p_core = np.exp(z) / np.sum(np.exp(z))
    
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

### `pi_14` → slot 1 (via `new_theory`)

**Description:** Strategy Mixture Theory (Environment-Adaptive Toolbox with Tallying Blend)

**Rationale:** Following the critic's advice, I removed the scale-invariant normalization of WADD weights (which divided by `max_c`). Instead, I scaled the centered validities by a factor of 2.0. This keeps the maximum possible weight at 1.0 (since validities are in [0.5, 1.0]), making it comparable to the pure Tallying weight of 1.0, but importantly preserves the absolute magnitude differences between environments. This will allow the `beta` parameter to scale choice probabilities according to the overall strength of validities, improving fits on compensatory experiments like Exps 4, 20, and 22.

**Parameters:**
  - `theta`: `[0.0, 30.0]`
  - `disp_threshold`: `[0.0, 0.5]`
  - `gamma`: `[0.0, 10.0]`
  - `alpha`: `[0.0, 1.0]`
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Strategy 1: Take-The-Best (TTB)
    # Inspect features in descending order of validity; stop at the first discriminating feature.
    order = np.argsort(val)[::-1]
    ttb_prob = np.array([0.5, 0.5])
    for idx in order:
        if a[idx] > b[idx]:
            ttb_prob = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            ttb_prob = np.array([0.0, 1.0])
            break
            
    # Strategy 2: Compensatory (Blend of WADD and Tallying)
    # Evaluate all features, weighting them by a blend of pure Tallying (equal weights) and WADD.
    gamma = float(parameters["gamma"])
    alpha = float(parameters["alpha"])
    centered_val = np.clip(val - 0.5, 1e-6, 0.5)
    
    # Scale validities to [0, 1] based on absolute magnitude, rather than normalizing by max
    scaled_val = centered_val * 2.0
        
    w_wadd = scaled_val ** gamma
    w = alpha * w_wadd + (1.0 - alpha) * 1.0
    
    comp_scores = np.array([np.sum(a * w), np.sum(b * w)])
    
    beta = float(parameters["beta"])
    z = beta * comp_scores
    z -= np.max(z)  # numerical stability
    e = np.exp(z)
    comp_prob = e / np.sum(e)
    
    # Strategy Mixture: Probabilistic selection between TTB and Compensatory based on environment
    # The probability of selecting TTB depends on the dispersion (std dev) of the validities.
    dispersion = float(np.std(val))
    theta = float(parameters["theta"])
    disp_threshold = float(parameters["disp_threshold"])
    
    z_disp = theta * (dispersion - disp_threshold)
    p_ttb = 1.0 / (1.0 + np.exp(-np.clip(z_disp, -20.0, 20.0)))
    
    p_core = p_ttb * ttb_prob + (1.0 - p_ttb) * comp_prob
    
    # Trembling hand error
    epsilon = float(parameters["epsilon"])
    n_opts = len(p_core)
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
