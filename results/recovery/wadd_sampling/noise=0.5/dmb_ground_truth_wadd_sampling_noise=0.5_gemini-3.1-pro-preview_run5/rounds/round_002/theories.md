# Round 2 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_3` — KILLED ✗

**Description:** Weighted Additive (WADD) Theory with Non-linear Subjective Weights: People evaluate options by considering all available features, weighting each by a subjective transformation of its validity. Rather than using raw validities, people subjectively distort them via an exponent (gamma). A gamma > 1 disproportionately emphasizes higher-validity cues (shifting behavior towards Take The Best), whereas a gamma < 1 flattens the weights (shifting behavior towards Tallying). The subjective value of an option is the weighted sum of its features, and choices are made probabilistically via a softmax over these values, with a lapse rate.

**Rationale:** Following the critic's diagnosis, bounding gamma at 10.0 produced slightly too much TTB-like behavior, whereas bounding it at 3.0 (in the rejected iteration) overcorrected and produced too much Tallying-like behavior. Setting the gamma range to [0.1, 6.0] provides a middle ground. This allows enough non-linear amplification of the validities to capture TTB-like choices without letting the model become entirely dominated by the top cue, enabling it to better match the intermediate match rates in both experiments.

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `gamma`: `[0.1, 6.0]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    weights = val ** gamma
    
    # Weighted additive sum for each option
    score_a = np.sum(a * weights)
    score_b = np.sum(b * weights)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


### slot 2 — `pi_4` — SURVIVED ✓

**Description:** Strategy Mixture Theory with Decoupled Determinism: Decision-makers probabilistically choose between Tallying and Take-The-Best on any given trial. Because Tallying operates on raw integer count differences (which can be large) while TTB operates on binary 1/0 differences, the two heuristics have different intrinsic scales. To account for this, the model uses independent inverse temperatures (beta_tally and beta_ttb) for each strategy. This allows the decision process to independently calibrate the determinism of each heuristic, avoiding artificial scale distortions when balancing the two strategies via the mixture weight.

**Rationale:** Following the critic's advice, the previous failed attempt to artificially normalize Tallying scores has been reverted. Instead, the scale discrepancy between Tallying (which produces large integer differences) and Take-The-Best (which produces binary 1/0 differences) is resolved by decoupling the softmax temperatures. By introducing independent `beta_tally` and `beta_ttb` parameters, the model can naturally calibrate the determinism of each heuristic during parameter fitting. This minimal edit addresses the asymmetric noise issue while maintaining the core mixture mechanism that successfully lowered the loss in Iteration 1.

**Parameters:**
  - `beta_tally`: `[0.1, 20.0]`
  - `beta_ttb`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `p_tally_weight`: `[0.0, 1.0]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    beta_tally = float(parameters["beta_tally"])
    beta_ttb = float(parameters["beta_ttb"])
    epsilon = float(parameters["epsilon"])
    p_tally_weight = float(parameters["p_tally_weight"])
    
    # --- Tallying Prediction ---
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores_tally = np.array([a_wins, b_wins])
    
    z_tally = beta_tally * (scores_tally - np.max(scores_tally))
    e_tally = np.exp(z_tally)
    p_tally = e_tally / np.sum(e_tally)
    
    # --- Take-The-Best (TTB) Prediction ---
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
        z_ttb = beta_ttb * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
    # --- Mixture & Noise ---
    p_mix = p_tally_weight * p_tally + (1.0 - p_tally_weight) * p_ttb
    p_final = (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])
    
    return p_final
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## Replacement

### `pi_5` → slot 1 (via `new_theory`)

**Description:** WADD / Take-The-Best Strategy Mixture Theory with Calibrated Determinism: Decision-makers probabilistically choose between a fully compensatory Weighted Additive (WADD) strategy and a non-compensatory Take-The-Best (TTB) strategy on any given trial. By mixing WADD and TTB, the model captures both dominance violations (via WADD) and choice probability plateaus (via TTB). Independent inverse temperatures allow each strategy to scale properly. To match the high level of equivocation in human data across multiple experiments, the determinism of these strategies is strongly bounded, ensuring predictions remain appropriately probabilistic.

**Rationale:** Retains the WADD + TTB mixture mechanism that successfully captured the direction of the experimental effects. Following the critic's feedback, we further reduce the upper bounds of `beta_wadd` and `beta_ttb` from 5.0 to 3.0. This minimal change continues to soften the determinism of both strategies, bringing the model's choice probabilities closer to the equivocal human baseline (~0.5) observed in Experiments 3, 4, and 5.

**Parameters:**
  - `beta_wadd`: `[0.0, 3.0]`
  - `beta_ttb`: `[0.0, 3.0]`
  - `p_wadd_weight`: `[0.0, 1.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    beta_wadd = float(parameters["beta_wadd"])
    beta_ttb = float(parameters["beta_ttb"])
    epsilon = float(parameters["epsilon"])
    p_wadd_weight = float(parameters["p_wadd_weight"])
    
    # --- WADD Prediction ---
    score_a = np.sum(a * val)
    score_b = np.sum(b * val)
    scores_wadd = np.array([score_a, score_b])
    
    z_wadd = beta_wadd * (scores_wadd - np.max(scores_wadd))
    e_wadd = np.exp(z_wadd)
    p_wadd = e_wadd / np.sum(e_wadd)
    
    # --- Take-The-Best (TTB) Prediction ---
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
        z_ttb = beta_ttb * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
    # --- Mixture & Noise ---
    p_mix = p_wadd_weight * p_wadd + (1.0 - p_wadd_weight) * p_ttb
    p_final = (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])
    
    return p_final
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```
