# Round 1 — Theories

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


### slot 2 — `pi_3` — KILLED ✗

**Description:** People make decisions between options by simply counting the total number of positive features (or cues) each option possesses, and choosing the option with the higher count. This 'Tallying' or Equal Weight heuristic completely ignores the relative validities or importance of different features, treating all available evidence as equally diagnostic. When options have an equal number of positive features, the decision maker guesses. Response noise is modeled via a softmax function over the feature counts and a uniform lapse rate. Parameter ranges allow for high levels of noise and even negative weights (beta) to capture empirical behavior where feature counts do not strongly drive choice, or where subjects might actively lean away from sheer feature counts.

**Rationale:** Following the critic's advice, the parameter range for beta has been expanded to [-5.0, 5.0]. This allows the model to capture the slight negative effect of feature counts observed in the empirical data for these specific experiments. While a negative beta represents a counter-intuitive preference for options with fewer features, it mathematically allows the Tallying mechanism to fit the empirical finding that subjects lean slightly away from the sheer feature count.

**Parameters:**
  - `beta`: `[-5.0, 5.0]`
  - `epsilon`: `[0.0, 1.0]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Tallying expects a (2, n_features) stimulus.")
        
    # Tallying: count the number of positive features (1s) for each option
    scores = np.sum(stim, axis=1)
    
    beta = float(parameters['beta'])
    epsilon = float(parameters['epsilon'])
    
    # Softmax over the tally scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
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

### `pi_4` → slot 2 (via `new_theory`)

**Description:** People make decisions by integrating all available features, weighting each positive feature by a rank-based subjective transformation of its stated validity. Specifically, cues are ranked by their validities (1 for highest), and the subjective weight is modeled as an inverse power function of the rank (1.0 / rank^gamma). This compensatory Rank-Weighted Additive strategy naturally scales between Tallying (when gamma = 0, all features are weighted equally) and Take The Best (when gamma is large, the highest-validity cue dominates). Because the top cue always has a weight of 1.0, the scores remain well-scaled, allowing the softmax temperature to effectively control decision determinism.

**Rationale:** Following the critic's feedback, we have replaced the power-law transformation of raw validities with a rank-based transformation. Cues are ranked by their given validities, and weights are assigned as `1.0 / (ranks ** gamma)`. This Rank-Weighted Additive approach ensures that the top cue always receives a well-scaled weight of 1.0, preventing the weights (and consequently the scores) from mathematically crushing to near-zero when `gamma` is large. This allows the model to smoothly transition to a sharp Take-The-Best-like strategy (necessary for Experiment 2) without distorting the softmax temperature or hurting the fits for Experiments 1, 3, and 4.

**Parameters:**
  - `gamma`: `[0.0, 20.0]`
  - `beta`: `[0.0, 10.0]`
  - `epsilon`: `[0.0, 1.0]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    validities = np.asarray(parameters['validities'], dtype=float)
    gamma = float(parameters['gamma'])
    beta = float(parameters['beta'])
    epsilon = float(parameters['epsilon'])
    
    # Rank cues by validity (1 for highest validity)
    order = np.argsort(-validities, kind='stable')
    ranks = np.empty_like(order, dtype=float)
    ranks[order] = np.arange(1, len(validities) + 1)
    
    # Subjective transformation based on ranks
    weights = 1.0 / (ranks ** gamma)
    
    # Weighted sum of features for each option
    scores = stim @ weights
    
    # Softmax choice rule with numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
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
