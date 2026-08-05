# Round 1 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** Decision-makers integrate all available information using a Weighted Additive (WADD) strategy, but scale evidence using the log-odds of cue validities. Rather than relying on a single best cue or ignoring cue validities, individuals compute an overall expected value for each option by taking the dot product of the option's features and the log-odds transformed validities. This transformation naturally stretches higher validities, balancing the influence of a single strong cue against multiple weaker ones. Choice is then executed stochastically via a softmax function, subject to occasional random lapses.

**Rationale:** Following the critic's feedback, the raw validities are transformed into log-odds before computing the expected value. This transformation gives exponentially more weight to highly valid cues, allowing the WADD model to better balance between TTB-favored (single high-validity cue) and Tallying-favored (multiple lower-validity cues) options. This adjustment prevents the model from overly mimicking Tallying and pulls the predictions towards the empirical ~0.50 choice proportion observed in the pit-trials.

**Parameters:**
  - `beta`: `[0.0, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Transform validities to log-odds to stretch higher validities
    # Clip to avoid division by zero or log(0) if validity is exactly 1.0
    val_clipped = np.clip(val, 0.0001, 0.9999)
    weights = np.log(val_clipped / (1.0 - val_clipped))
    
    # Calculate the weighted sum of features (expected value) for each option
    ev_a = np.dot(a, weights)
    ev_b = np.dot(b, weights)
    scores = np.array([ev_a, ev_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate lapse rate
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


### slot 2 — `pi_2` — KILLED ✗

**Description:** People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


**Rationale:** (none)

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    # Paper-faithful Tallying heuristic (Dawes 1979; Gigerenzer &
    # Goldstein 1999). Stimulus is the pair of option feature vectors
    # for the current trial: array-like of shape (2, n_features),
    # with row 0 = option A, row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    # Count strict feature-wise wins; ties contribute to neither option.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. When
    # a_wins == b_wins the softmax is exactly uniform regardless of
    # beta, which is the correct behavior for an undiscriminating
    # tally.
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


## Replacement

### `pi_4` → slot 2 (via `new_theory`)

**Description:** Cognitive Overload / Random Choice: When faced with multiple conflicting binary cues and explicitly stated validities, subjects experience cognitive overload or lack sufficient motivation to integrate the information systematically. Consequently, their decision-making process collapses into pure random guessing, treating both options as equally likely to be chosen regardless of their specific feature values.

**Rationale:** The empirical data across all four experiments show strict-preference metrics hovering very close to 0.5 (e.g., 0.4900, 0.5020, 0.5125, 0.5067). This indicates that subjects' choices do not systematically align with deterministic strategies like Take-The-Best, Tallying, or WADD under these specific experimental conditions. The Cognitive Overload theory naturally explains this by positing that the complexity of integrating multiple conflicting cues with explicit validities leads to a collapse into random guessing. Modeling this as a uniform random choice (equivalent to an epsilon lapse rate of 1.0) perfectly captures the ~0.5 empirical performance across all experiments.

**Parameters:**
  - `lapse_rate`: `{1.0}`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    # The theory posits that cognitive overload causes subjects to guess randomly.
    # We extract the lapse_rate parameter to satisfy the parameter mapping requirement.
    lapse_rate = float(parameters["lapse_rate"])
    
    # Always return a uniform distribution over the two options.
    return np.array([0.5, 0.5])
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```
