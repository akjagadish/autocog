# Round 13 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_15` — KILLED ✗

**Description:** Weighted Sequential Evidence Accumulation with Self-Excitation/Decay (Leaky Accumulator). Decision-makers process information sequentially in descending order of feature validity. Each feature's evidence is weighted by its validity and added to a running accumulator. Crucially, previously accumulated evidence can either 'leak' (decay) or self-excite (amplify) as new features are evaluated. A choice is made either when the accumulator hits a predefined threshold or when all features are exhausted. Self-excitation allows the model to capture strong primacy effects even when the decision threshold is not reached.

**Rationale:** Following the latest feedback, I expanded the 'leak' parameter range to [-1.0, 1.0]. In a leaky accumulator, a negative leak acts as self-excitation, amplifying previously accumulated evidence as time goes on. This naturally allows the exact same equation to produce strong primacy effects even when the decision threshold is not hit, directly addressing the model's severe failures on Experiments 18, 22, and 26 without requiring complex new decay equations or breaking the base mechanism.

**Parameters:**
  - `threshold`: `[0.0, 5.0]`
  - `leak`: `[-1.0, 1.0]`
  - `gamma`: `[0.0, 5.0]`
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
    
    threshold = float(parameters["threshold"])
    leak = float(parameters["leak"])
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Evaluate features in descending order of validity
    order = np.argsort(val)[::-1]
    
    A = 0.0
    for idx in order:
        diff = a[idx] - b[idx]
        weight = val[idx] ** gamma
        
        # Leaky accumulation (or self-excitation if leak < 0)
        A = A * (1.0 - leak) + weight * diff
        
        # Stopping rule
        if abs(A) >= threshold and abs(A) > 1e-9:
            break
            
    scores = np.array([A, -A])
    
    # Softmax conversion to probabilities
    z = beta * scores
    z -= np.max(z)  # For numerical stability
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

### `pi_16` → slot 1 (via `new_theory`)

**Description:** Decision-makers use a Normalized Weighted Sequential Evidence Accumulation strategy with a stopping rule. They inspect features one by one in descending order of their validity. They accumulate the differences between the options weighted by the features' validities, which are non-linearly scaled and normalized to sum to 1. This normalization ensures the evidence scale is consistent across experiments with varying numbers of features. If the absolute accumulated evidence reaches or exceeds a specific threshold (bounded between 0 and 1), they stop and make a choice based on that evidence. If the threshold is not reached, they evaluate all features and decide based on the final tally.

**Rationale:** Applying the minimal-diff edit suggested by the critic: replacing the zero-centered validity weighting with a raw validity power-law weighting that is normalized to sum to 1. This bounds the maximum possible accumulated evidence regardless of the number of features or their raw validity values. The threshold parameter range is updated to [0.0, 1.0] to match this normalized scale, ensuring the stopping rule triggers consistently across different experimental designs.

**Parameters:**
  - `threshold`: `[0.0, 1.0]`
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `gamma`: `[0.1, 5.0]`
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
    gamma = float(parameters["gamma"])
    
    # Normalize validities raised to gamma so they sum to 1
    weights = (val ** gamma) / np.sum(val ** gamma)
    
    diff = a - b
    accumulated_evidence = 0.0
    
    for idx in order:
        accumulated_evidence += diff[idx] * weights[idx]
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
