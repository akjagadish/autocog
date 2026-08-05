# Round 9 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_11` — SURVIVED ✓

**Description:** Unique Features Weakest-Link: Decision-makers simplify choices by first cancelling out features shared by both options. They then evaluate each option based solely on its unique features, computing the average subjective validity of these features but applying a disproportionate penalty based on the option's 'weakest link' (the gap between its best and worst unique features).

**Rationale:** The theory posits that decision-makers first simplify choices by cancelling out any features shared by both options, a process known as cue-cancellation. After stripping away these commonalities, they evaluate the remaining unique features of each option. This evaluation is based on the average subjective validity of the unique features, but is heavily penalized by the 'weakest link' (the lowest validity unique feature) relative to the best unique feature. This theory elegantly explains why adding shared features has no effect on choice probabilities (solving Experiment 17, where the prior Weakest Link model failed catastrophically) while naturally capturing the variance-aversion and dilution effects observed in other experiments through the weakest-link penalty applied to unique features.

**Parameters:**
  - `gamma`: `[0.1, 10.0]`
  - `lambda_weak`: `[0.0, 10.0]`
  - `beta`: `[0.1, 50.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    lambda_weak = float(parameters["lambda_weak"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Transform validities into subjective weights
    w = val ** gamma
    
    # Cancel out shared features
    shared = (a > 0) & (b > 0)
    unique_a = a.copy()
    unique_a[shared] = 0
    unique_b = b.copy()
    unique_b[shared] = 0
    
    def get_score(unique_x):
        active_w = w[unique_x > 0]
        if len(active_w) == 0:
            return 0.0
        
        mean_w = np.mean(active_w)
        min_w = np.min(active_w)
        max_w = np.max(active_w)
        
        # Averaging baseline with a penalty based on the weakest link's distance from the best feature
        return mean_w - lambda_weak * (max_w - min_w)
        
    score_a = get_score(unique_a)
    score_b = get_score(unique_b)
    
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule
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
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


### slot 2 — `pi_9` — KILLED ✗

**Description:** Weakest Link (Worst-Case Focus): Decision-makers evaluate an option primarily by averaging the subjective validities of its present features, but they apply a disproportionate penalty based on the option's 'weakest link' (the lowest validity active feature). Specifically, the penalty is proportional to the gap between the option's best feature and its weakest feature. This cognitive mechanism reflects a worst-case focus where attention is drawn to the most inferior attribute, naturally predicting both the dilution effect (adding weak features reduces the mean and increases the weakest-link penalty) and variance aversion (options with tighter feature clusters have smaller weakest-link penalties).

**Rationale:** Following the arbiter's recommendation, this theory implements a 'Weakest Link' mechanism. Instead of computing a global mathematical variance across all active features (which may be cognitively implausible), decision-makers anchor on the average quality of the option but are heavily influenced by the worst-case feature (the lowest validity active feature). The penalty is formalized as the gap between the maximum and minimum active validities. This naturally captures the dilution effect (adding a low-validity feature drastically pulls down the minimum and the mean) and variance aversion (options with high variance have a larger gap between their best and weakest links, leading to a larger penalty), providing a strong mechanistic competitor to holistic variance computation.

**Parameters:**
  - `gamma`: `[0.1, 10.0]`
  - `lambda_weak`: `[0.0, 10.0]`
  - `beta`: `[0.1, 50.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    lambda_weak = float(parameters["lambda_weak"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Transform validities into subjective weights
    w = val ** gamma
    
    def get_score(x):
        active_w = w[x > 0]
        if len(active_w) == 0:
            return 0.0
        
        mean_w = np.mean(active_w)
        min_w = np.min(active_w)
        max_w = np.max(active_w)
        
        # Averaging baseline with a penalty based on the weakest link's distance from the best feature
        return mean_w - lambda_weak * (max_w - min_w)
        
    score_a = get_score(a)
    score_b = get_score(b)
    
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule
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
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## Replacement

### `pi_12` → slot 2 (via `new_theory`)

**Description:** Strict Averaging of Active Features: Decision-makers evaluate an option by computing the simple mean of the subjective validities of all features present in that option. This holistic averaging naturally produces the dilution effect (adding weak features to a strong subset lowers the average) while preserving relative ordinal preferences when shared features are added to both options, avoiding the catastrophic preference reversals caused by range-based penalties.

**Rationale:** Following the arbiter's recommendation, this model implements a strict averaging mechanism. The subjective value of an option is exactly the mean of the subjective validities (transformed via a power parameter 'gamma') of its active features. This naturally accounts for the dilution effect seen in Experiment 9, where adding a weak feature to a strong subset lowers the option's overall value. Crucially, unlike range-based or weakest-link penalties, simple averaging preserves the relative ordinal preference between options when a shared weak feature is added to both, directly addressing the mechanistic failures identified in Experiments 1, 2, and 19.

**Parameters:**
  - `gamma`: `[0.1, 10.0]`
  - `beta`: `[0.1, 25.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Transform validities into subjective weights
    w = val ** gamma
    
    # Calculate the mean subjective validity of active features for each option
    score_a = np.mean(w[a > 0]) if np.sum(a) > 0 else 0.0
    score_b = np.mean(w[b > 0]) if np.sum(b) > 0 else 0.0
    
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule
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
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```
