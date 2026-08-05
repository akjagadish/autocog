# Round 4 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_1` — SURVIVED ✓

**Description:** People compare two options by consulting cues one at a time in order of validity, stopping at the first cue that discriminates between the two options. That cue alone determines the choice: the option with the higher value on the discriminating cue wins, and no other cue is consulted. Cues with lower validity are never reached when a higher-validity cue already discriminates, so Take The Best is a "one-reason" decision rule — only a single feature is ever used on any given choice. Because only the sign of the comparison on the top discriminating cue matters, TTB ignores both the magnitude of that difference and all information on lower-validity cues, making it maximally frugal in the use of evidence. Cue validities are subjective and can be learned, inferred from instructions, or fixed by task structure. When no cue discriminates (all feature-wise comparisons tie) the learner has no basis for preference and must guess. Response noise enters through a softmax over the binary TTB score (winner = 1, loser = 0) with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


**Rationale:** (none)

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    # Paper-faithful Take The Best (Gigerenzer & Goldstein 1996).
    # Stimulus is the pair of option feature vectors for the current
    # trial: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B. Cue cascade: features are consulted in order
    # of descending validity; the first discriminating cue (strict
    # inequality) determines the winner; if no cue discriminates,
    # the model guesses uniformly. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )
    # Descending validity; argsort is stable so validity ties break
    # toward the earlier feature index.
    cue_order = np.argsort(-val, kind="stable").tolist()

    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        if b[j] > a[j]:
            winner = 1
            break

    if winner is None:
        # No discriminating cue — pure guess.
        return np.ones(2) / 2.0

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the
    # binary TTB score this collapses to sigmoid(beta) for the winner,
    # giving a direct mapping from beta onto the paper's flip-noise
    # levels (beta=0 ↔ 50/50; beta ≫ 1 ↔ deterministic).
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)
```


### slot 2 — `pi_6` — KILLED ✗

**Description:** Strategy Mixture Theory: The population is heterogeneous in its decision-making strategies. A large majority of individuals (around 90%) rely on the strict, non-compensatory Take The Best (TTB) heuristic, which explains the dominant lexicographic patterns in most experiments. However, a smaller proportion of the population (around 10%) uses a compensatory Weighted Additive (WADD) strategy, integrating all available cues weighted by their validities. This mixture preserves the high accuracy of TTB on benchmark tasks while successfully capturing the right-tail sensitivity to opposing cues observed in certain experiments.

**Rationale:** Following the critic's advice, we build on the accepted Iteration 1 base but reduce the hardcoded WADD proportion from 25% to 10% (`wadd_prop < 0.10`). Because `wadd_prop` is drawn uniformly from `[0.0, 1.0]` per subject, this ensures only ~10% of the simulated population acts in a compensatory manner. This smaller minority is sufficient to capture the right-tail sensitivity in Experiment 5 while preventing the aggregate predictions from drifting too far from the dominant strict lexicographic baseline seen in Experiments 3, 4, 6, and 8.

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `wadd_prop`: `[0.0, 1.0]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    wadd_prop = float(parameters["wadd_prop"])
    
    # Between-subject mixture: 10% of the population uses WADD, 90% uses TTB
    is_wadd = (wadd_prop < 0.10)
    
    if is_wadd:
        # Weighted Additive (WADD) strategy
        val_clip = np.clip(val, 0.001, 0.999)
        log_odds = np.log(val_clip / (1.0 - val_clip))
        ev = np.sum(log_odds * (a - b))
        if ev > 1e-5:
            scores = np.array([1.0, 0.0])
        elif ev < -1e-5:
            scores = np.array([0.0, 1.0])
        else:
            scores = np.array([0.5, 0.5])
    else:
        # Take The Best (TTB) strategy
        cue_order = np.argsort(-val, kind="stable").tolist()
        winner = None
        for j in cue_order:
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
                
        if winner == 0:
            scores = np.array([1.0, 0.0])
        elif winner == 1:
            scores = np.array([0.0, 1.0])
        else:
            scores = np.array([0.5, 0.5])
            
    # Apply softmax response noise and lapse rate
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / e.sum()
    
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

**Description:** Sequential Evidence Accumulation with Confidence Threshold: Decision-makers evaluate cues sequentially in descending order of validity, accumulating log-odds evidence for each option. The search terminates as soon as the evidence difference exceeds a subject-specific confidence threshold. A low threshold results in pure Take-The-Best (lexicographic) behavior, while a high threshold allows for compensatory integration of multiple cues, naturally capturing both dominant one-reason decision making and occasional compensatory behavior without relying on a discrete mixture of strategies.

**Rationale:** To correct the model's overestimation of compensatory (WADD) behavior, we tightened the parameter range for the confidence threshold `theta` from `[0.0, 3.0]` to `[0.0, 1.5]`. Since typical validities (e.g., 0.8) have log-odds around 1.38, a lower upper bound ensures that the first discriminating cue is usually sufficient to cross the threshold, preserving predominantly lexicographic behavior across experiments while still allowing occasional compensatory effects when cues are weaker.

**Parameters:**
  - `theta`: `[0.0, 1.5]`
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    theta = float(parameters["theta"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Calculate log-odds evidence for each cue
    val_clip = np.clip(val, 0.5001, 0.9999)
    w = np.log(val_clip / (1.0 - val_clip))
    
    # Sort cues in descending order of validity
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    delta = 0.0
    winner = None
    
    for j in cue_order:
        delta += w[j] * (a[j] - b[j])
        if delta >= theta:
            winner = 0
            break
        elif delta <= -theta:
            winner = 1
            break
            
    if winner is None:
        # If all cues are exhausted without crossing the threshold, pick the one with more evidence
        if delta > 1e-5:
            winner = 0
        elif delta < -1e-5:
            winner = 1
            
    if winner == 0:
        scores = np.array([1.0, 0.0])
    elif winner == 1:
        scores = np.array([0.0, 1.0])
    else:
        scores = np.array([0.5, 0.5])
        
    z = beta * scores
    z = z - np.max(z)
    e = np.exp(z)
    p_core = e / e.sum()
    
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
