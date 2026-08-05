# Round 2 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** Take-The-Best (TTB) heuristic: People make decisions between multi-attribute options by ranking features according to their validities and comparing the options lexicographically. The decision-maker examines the feature with the highest validity first; if one option is strictly better on that feature, it is chosen immediately and no further features are considered. If there is a tie, they move to the second most valid feature, and so on. This non-compensatory, one-reason decision making process implies that a single highly valid cue can completely determine the choice, overriding any number of smaller advantages on less valid cues.

**Rationale:** Following the arbiter's recommendation, this proposes the Take-The-Best (TTB) heuristic. Unlike Tallying (which ignores validities) or WADD (which computes a compensatory sum), TTB is a non-compensatory lexicographic rule. It evaluates features sequentially by validity, making a deterministic choice based solely on the first discriminating feature. Response noise is handled via a standard lapse rate epsilon. This captures the strong directional effects seen in the data where decisions are driven entirely by the most informative cue.

**Parameters:**
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Rank features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    choice = None
    for idx in order:
        if a[idx] > b[idx]:
            choice = 0
            break
        elif b[idx] > a[idx]:
            choice = 1
            break
            
    epsilon = float(parameters["epsilon"])
    n_opts = 2
    
    if choice is None:
        p_core = np.ones(n_opts) / n_opts
    else:
        p_core = np.zeros(n_opts)
        p_core[choice] = 1.0
        
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


### slot 2 — `pi_4` — KILLED ✗

**Description:** Probabilistic Take-The-Best (PTTB): People evaluate cues sequentially to make decisions, but the sequence is stochastic rather than strictly deterministic. The probability of sampling a cue is proportional to an exponential function of its subjective validity. When sampling without replacement, the probability that the first discriminating cue encountered is cue $i$ is exactly proportional to its weight among all discriminating cues. This model bridges Tallying (when temperature is high/gamma is 0, all cues are equally likely to be the deciding one) and deterministic Take-The-Best (when gamma is large, the highest validity cue almost always determines the choice), providing a nuanced non-compensatory heuristic.

**Rationale:** Following the critic's feedback, the parameter ranges for gamma and epsilon have been adjusted to find the sweet spot between iteration 1 (under-predicting deterministic choices) and iteration 2 (over-predicting). Setting gamma to [0.0, 35.0] and epsilon to [0.0, 0.3] should soften the model just enough to perfectly match the ~0.80-0.85 empirical match rates without falling back into excessive random guessing.

**Parameters:**
  - `gamma`: `[0.0, 35.0]`
  - `epsilon`: `[0.0, 0.3]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("PTTB expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    epsilon = float(parameters["epsilon"])
    
    # Identify cues that discriminate between the two options
    discrim = (a != b)
    
    if not np.any(discrim):
        # No discriminating cues, guess uniformly
        p_core = np.array([0.5, 0.5])
    else:
        # The probability of a discriminating cue being the first one found
        # is proportional to exp(gamma * validity).
        val_discrim = validities[discrim]
        # Max-subtraction for numerical stability
        z = gamma * (val_discrim - np.max(val_discrim))
        w = np.exp(z)
        w = w / np.sum(w)
        
        # The probability of choosing an option is the sum of the probabilities
        # of the discriminating cues that favor it.
        p_a = np.sum(w[a[discrim] > b[discrim]])
        p_b = np.sum(w[b[discrim] > a[discrim]])
        
        p_core = np.array([p_a, p_b])
        
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## Replacement

### `pi_5` → slot 2 (via `new_theory`)

**Description:** Naïve Bayes / Log-Odds Weighted Additive (WADD) model: Decision makers integrate all available cues by weighting them according to their log-odds (the theoretically optimal Bayesian weights for independent cues). This transformation naturally amplifies cues with high validities, bridging compensatory integration and TTB-like non-compensatory behavior without requiring an extra free parameter for the non-linearity. A softmax choice rule then translates the difference in the options' overall subjective values into choice probabilities.

**Rationale:** Following the critic's advice, the arbitrary exponential transformation with parameter `gamma` has been replaced by the theoretically grounded log-odds (Naïve Bayes) transformation. This transformation naturally scales the validities such that high-validity cues are strongly amplified, mimicking TTB-like behavior, while still allowing compensatory integration of multiple lower-validity cues. By removing `gamma` and widening the `beta` range to [0.1, 25.0], the model retains the ability to make highly deterministic choices without the risk of over-compressing weights, leading to a more principled and robust soft-compensatory WADD formulation.

**Parameters:**
  - `beta`: `[0.1, 25.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Expected a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Transform validities using log-odds (Naïve Bayes weights)
    v_clipped = np.clip(validities, 1e-5, 1.0 - 1e-5)
    w = np.log(v_clipped / (1.0 - v_clipped))
    
    # Calculate overall subjective value for each option
    score_a = np.sum(a * w)
    score_b = np.sum(b * w)
    
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
```

**`policy(probs)`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```
