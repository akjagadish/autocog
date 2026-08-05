# Round 3 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_5` — KILLED ✗

**Description:** Strategy Selection (Mixture of TTB and WADD): Decision-makers are not strictly bound to a single decision strategy. Instead, there is a mixture of strategies used either across the population or within individuals on a trial-by-trial basis. Specifically, individuals choose between a non-compensatory heuristic (Take-The-Best) and a compensatory strategy (Weighted Additive Model). TTB relies solely on the highest-validity discriminating feature, while WADD computes a weighted sum of all features using their validities. The parameter 'p_wadd' dictates the probability of using WADD over TTB, allowing the model to capture both strict one-reason decision making and sensitivity to lower-validity cues when they strongly favor one option. The baseline probability of using WADD is restricted to reflect that non-compensatory heuristics are predominant.

**Rationale:** Following the critic's feedback, the Strategy Selection Model is maintained, but the prior range for 'p_wadd' is restricted from [0.0, 1.0] to [0.1, 0.5]. This centers the expected probability of using the compensatory WADD strategy around 0.3, which closely matches the ~0.31-0.32 empirical response rates observed in Experiments 3 and 4 where WADD and TTB diverge. This minimal edit ensures the average simulated subject relies predominantly on TTB while still exhibiting the necessary sensitivity to lower-validity cues.

**Parameters:**
  - `p_wadd`: `[0.1, 0.5]`
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
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # --- Take-The-Best (TTB) Strategy ---
    order = np.argsort(validities)[::-1]
    a_wins = 0.0
    b_wins = 0.0
    for idx in order:
        if a[idx] > b[idx]:
            a_wins = 1.0
            break
        elif b[idx] > a[idx]:
            b_wins = 1.0
            break
            
    if a_wins == 0.0 and b_wins == 0.0:
        p_ttb = np.array([0.5, 0.5])
    else:
        p_ttb = np.array([a_wins, b_wins])
        
    # --- Weighted Additive (WADD) Strategy ---
    scores = stim @ validities
    beta = float(parameters["beta"])
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_wadd_dist = e / e.sum()
    
    # --- Mixture Model ---
    p_wadd = float(parameters["p_wadd"])
    p_core = p_wadd * p_wadd_dist + (1.0 - p_wadd) * p_ttb
    
    # --- Lapse Rate ---
    epsilon = float(parameters["epsilon"])
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


### slot 2 — `pi_4` — SURVIVED ✓

**Description:** Stochastic Take-The-Best (Search Error)

**Rationale:** The arbiter suggested replacing WADD with Tallying. However, the leaderboard explicitly demonstrates that Tallying (pi_1) completely fails to capture the data (overall score 0.0), predicting response rates of ~0.85 in Experiments 3 and 4 where human data shows ~0.32. In contrast, Take The Best (pi_3) fits the data exceptionally well (score 1.0). Therefore, I am ignoring the feedback to implement Tallying. Instead, I propose a 'Stochastic Take-The-Best' theory. This model assumes decision-makers search through features in descending order of validity, but with a small probability of skipping a feature (search error or attention lapse) before finding a discriminating one. This maintains the core non-compensatory mechanism of TTB that successfully explains the human data, while adding a realistic cognitive noise parameter to slightly soften the strict determinism of pi_3 and better align with the empirical targets.

**Parameters:**
  - `p_skip`: `[0.0, 0.5]`
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

### `pi_6` → slot 1 (via `new_theory`)

**Description:** Feature Value Averaging (Dilution Effect): Decision-makers do not merely sum the evidence (validities) of all positive features; instead, they compute a partially or fully averaged value of the positive features. Adding lower-validity features to an option 'dilutes' its overall perceived quality, potentially making it less attractive than an option with fewer, but higher-validity, features. This naturally accounts for empirical effects where adding positive features paradoxically decreases an option's choice probability.

**Rationale:** The arbiter recommended a theory based on 'Feature Value Averaging' or a 'Dilution Effect'. This model introduces a parameter `gamma` that modulates the denominator of the value function. When `gamma` > 0, an option with many low-validity features experiences a drop in its overall score because the sum of validities is divided by the number of positive features raised to `gamma`. This mathematically instantiates the dilution effect, predicting that Option A (relying on a single high-validity feature) can beat Option B (which has many low-validity features) simply because B's average validity is dragged down. This elegantly explains the paradoxical results in Experiments 5, 6, and 8 where adding positive features to an option decreases its preference.

**Parameters:**
  - `gamma`: `[0.0, 2.0]`
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
        
    validities = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    scores = np.zeros(2)
    for i in range(2):
        n_pos = np.sum(stim[i])
        if n_pos > 0:
            # When gamma=0, this is Weighted Additive (WADD).
            # When gamma=1, this is pure Feature Averaging.
            scores[i] = np.sum(stim[i] * validities) / (n_pos ** gamma)
        else:
            scores[i] = 0.0
            
    # Softmax choice rule
    z = beta * (scores - np.max(scores))
    p = np.exp(z)
    p_core = p / np.sum(p)
    
    n_opts = 2
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
