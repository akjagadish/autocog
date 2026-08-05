# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_5") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_5" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
Take-The-Best (TTB) proposes that individuals use a non-compensatory lexicographic heuristic for decision making. They search through features in descending order of their validity and base their choice entirely on the first feature that discriminates between the two options, ignoring all remaining features. If no feature discriminates, they guess. Response noise is incorporated via a softmax function over the resulting binary scores and a lapse rate for random errors.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    scores = np.array([0.0, 0.0])
    
    # Find the first discriminating feature
    for idx in order:
        if a[idx] > b[idx]:
            scores[0] = 1.0
            break
        elif b[idx] > a[idx]:
            scores[1] = 1.0
            break
            
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Blend with uniform lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_5
Weighted Additive (WADD) model with Log-Odds Weights: Decision makers integrate all available information by computing a fully compensatory weighted sum of the features for each option. To properly scale the importance of each cue, objective validities (probabilities) are transformed into log-odds. This ensures that non-predictive cues (validity = 0.5) receive a weight of zero and do not distort the evaluation. The option with the higher weighted sum is favored, with choice probabilities generated via a softmax function to account for decision noise, alongside a uniform lapse rate for random errors.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Transform validities to log-odds for proper weighting
    # Clip to avoid log(0) or division by zero
    v_clipped = np.clip(validities, 1e-5, 1.0 - 1e-5)
    weights = np.log(v_clipped / (1.0 - v_clipped))
    
    # WADD: compute the weighted sum of features for each option
    scores = stim @ weights
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Blend with uniform lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probs = np.asarray(probabilities, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.8, 0.75, 0.65]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 4: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 7: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 8: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]

**Rationale:** This design systematically contrasts the non-compensatory Take-The-Best (TTB) model with the fully compensatory Weighted Additive (WADD) model using log-odds weights. By setting validities to [0.95, 0.85, 0.80, 0.75, 0.65], we create a steep but surmountable gradient in log-odds weights. TTB will always choose the option favored by the single highest-validity discriminating feature. WADD, however, integrates all features, allowing a coalition of lower-validity features to outweigh a single higher-validity feature. The trials include extreme conflicts (where the best feature is pitted against all others), moderate conflicts (where the best feature is pitted against a subset of lower features), and congruent trials where both models agree. This provides a robust quantitative dissociation of the two models.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.15884353741496599, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.2318181818181818, '((1, 0, 0, 0, 0), (0, 1, 1, 0, 0))|0': 0.15529411764705883, '((1, 0, 0, 0, 0), (0, 1, 1, 0, 0))|1': 0.2416, '((1, 0, 0, 0, 1), (0, 1, 1, 1, 0))|0': 0.1573109243697479, '((1, 0, 0, 0, 1), (0, 1, 1, 1, 0))|1': 0.2512, '((0, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.15580926796507724, '((0, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.25241157556270094, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.15680973301791146, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.30109204368174725, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.16162361623616237, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.24067796610169492, '((0, 1, 0, 1, 0), (0, 0, 1, 0, 1))|0': 0.1705662936588674, '((0, 1, 0, 1, 0), (0, 0, 1, 0, 1))|1': 0.250384024577573, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.16967871485943775, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.23529411764705882}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0


### RESULTS
- Predicted under pi_3 (simulated): 0.0011 (var=0.0002)
- Predicted under pi_5 (simulated): 0.1259 (var=0.0023)
- Observed on real data: 0.0017 (var=0.0001)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.92, 0.82, 0.78, 0.72, 0.65]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 6: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 7: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 8: A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Rationale:** To quantitatively dissociate the Weighted Additive (WADD) model from Take-The-Best (TTB), this design uses five features with validities that produce a specific profile of log-odds weights. TTB makes decisions based solely on the highest-validity discriminating feature, entirely ignoring the rest. WADD, using log-odds transformations of the validities, integrates all information. By carefully selecting the validities and constructing trials where the single best feature favors one option but a coalition of lower-validity features favors the other, we can create strong adversarial conditions. For example, WADD's compensatory nature allows the sum of the second, third, and fourth features to outweigh the first feature, whereas TTB will strictly follow the first feature. We also include trials where the models agree to help constrain the estimates of decision noise.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.8635346756152126, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.8649845064187693, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.8753918495297806, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.8646245059288538, '((1, 0, 0, 0, 0), (0, 1, 1, 0, 1))|0': 0.8346456692913385, '((1, 0, 0, 0, 0), (0, 1, 1, 0, 1))|1': 0.8620268620268621, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|0': 0.2277542372881356, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|1': 0.17996987951807228, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.8466367713004485, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.8631790744466801, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.7530054644808744, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.7981378026070763, '((1, 0, 0, 0, 1), (0, 1, 1, 0, 0))|0': 0.2550335570469799, '((1, 0, 0, 0, 1), (0, 1, 1, 0, 0))|1': 0.2139689578713969, '((0, 1, 0, 0, 0), (1, 0, 0, 0, 0))|0': 0.8418688230008985, '((0, 1, 0, 0, 0), (1, 0, 0, 0, 0))|1': 0.856453558504222}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0


### RESULTS
- Predicted under pi_3 (simulated): 0.1799 (var=0.0045)
- Predicted under pi_5 (simulated): 0.0006 (var=0.0001)
- Observed on real data: 0.2047 (var=0.0037)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
P_REF = {'((1, 0, 1, 0, 0), (0, 1, 0, 1, 0))|0': 0.5018703241895262, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 0))|1': 0.5100200400801603, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.13202933985330073, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.13440514469453377, '((0, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.1417437895762299, '((0, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.13316095669036845, '((0, 0, 0, 1, 1), (1, 1, 1, 0, 0))|0': 0.8727193744569939, '((0, 0, 0, 1, 1), (1, 1, 1, 0, 0))|1': 0.8713405238828967, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.8623737373737373, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.8715277777777778, '((1, 0, 0, 0, 1), (0, 1, 1, 0, 0))|0': 0.507400828892836, '((1, 0, 0, 0, 1), (0, 1, 1, 0, 0))|1': 0.4845630559916274, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 1))|0': 0.4828744123572868, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 1))|1': 0.4870237437879624, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 0))|0': 0.523680649526387, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 0))|1': 0.49858623939679547}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.1100 (var=0.0022)
**Predicted under pi_3:** 0.1011 (var=0.0025)
**Predicted under pi_5:** 0.1057 (var=0.0017)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]

**Metric**
```python
P_REF = {'((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.5449591280653951, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.6626633698339809, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.39959839357429716, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.45427728613569324, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|0': 0.38930517711171664, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|1': 0.4015918958031838, '((1, 0, 0, 1, 0), (0, 1, 1, 0, 0))|0': 0.49880260006842286, '((1, 0, 0, 1, 0), (0, 1, 1, 0, 0))|1': 0.43356139719121356, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 0))|0': 0.5448098001289491, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 0))|1': 0.5173210161662818}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.0623 (var=0.0021)
**Predicted under pi_3:** 0.0744 (var=0.0030)
**Predicted under pi_5:** 0.0812 (var=0.0033)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.16174466151749206, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.18656182987848463, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.16737698566447112, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.20804710500490678, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|0': 0.8371098760153912, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|1': 0.7929240374609782, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.15610766045548655, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.20337552742616033, '((1, 0, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.15672178289000718, '((1, 0, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.2114914425427873, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.16711486746062235, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.18856569709127383, '((1, 1, 0, 0, 0), (0, 0, 0, 1, 1))|0': 0.18994413407821228, '((1, 1, 0, 0, 0), (0, 0, 0, 1, 1))|1': 0.17244846656611362, '((0, 0, 0, 1, 0), (1, 0, 0, 0, 0))|0': 0.8334047109207708, '((0, 0, 0, 1, 0), (1, 0, 0, 0, 0))|1': 0.8031620553359684}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.0045 (var=0.0002)
**Predicted under pi_3:** 0.0004 (var=0.0002)
**Predicted under pi_5:** 0.0520 (var=0.0005)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.8224527150701647, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.8326309452137267, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.6560088202866593, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.5923852183650616, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.6092219020172911, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.6123324396782842, '((0, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.3986083499005964, '((0, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.3822418136020151, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.6947314049586777, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.6442307692307693, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|0': 0.17918088737201365, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|1': 0.1498371335504886, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|0': 0.4097051597051597, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|1': 0.3433062880324544, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|0': 0.336104513064133, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|1': 0.33611691022964507}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.1288 (var=0.0025)
**Predicted under pi_3:** 0.1342 (var=0.0035)
**Predicted under pi_5:** 0.0727 (var=0.0013)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]

**Metric**
```python
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.1551562792438705, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.2154011847065159, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 1))|0': 0.834345186470078, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 1))|1': 0.8064142194744977, '((1, 0, 0, 0, 0), (0, 1, 0, 0, 0))|0': 0.16761862917398945, '((1, 0, 0, 0, 0), (0, 1, 0, 0, 0))|1': 0.18693353474320243, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.17256433823529413, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.18720565149136578}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.0024 (var=0.0003)
**Predicted under pi_3:** 0.0010 (var=0.0002)
**Predicted under pi_5:** 0.1134 (var=0.0020)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Metric**
```python
P_REF = {'((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.6228886590830748, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.819935691318328, '((1, 0, 1, 1, 1), (0, 1, 0, 0, 0))|0': 0.15285379202501956, '((1, 0, 1, 1, 1), (0, 1, 0, 0, 0))|1': 0.12571610439210693, '((1, 0, 0, 1, 0), (0, 1, 1, 0, 1))|0': 0.39766081871345027, '((1, 0, 0, 1, 0), (0, 1, 1, 0, 1))|1': 0.6946693657219973, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.3609512850019179, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.7132234076947948, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.5852514919011083, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.8163064833005894}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.0774 (var=0.0008)
**Predicted under pi_3:** 0.0633 (var=0.0013)
**Predicted under pi_5:** 0.0238 (var=0.0004)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all eight experiments, THEORY 1 (Take-The-Best, pi_3) consistently and accurately predicts the observed metric values. In contrast, THEORY 2 (Weighted Additive, pi_5) fails dramatically on several experiments, particularly Experiments 1, 2, 5, 6, 7, and 8. For instance, in Experiment 2, pi_5 predicts a metric of 0.0006 while the observed data is 0.2047, which pi_3 closely anticipates (0.1799). The data strongly supports a non-compensatory, lexicographic decision process over a fully compensatory log-odds integration. Because pi_5 is degenerate and unable to capture the variance in the data, it should be replaced with a new theoretical alternative.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a new theory to replace the Weighted Additive model. Since Take-The-Best (THEORY 1) is highly successful, the new theory should be a strong competing heuristic from the fast-and-frugal heuristics literature, such as the 'Tallying' (Equal Weights) heuristic. Tallying ignores cue validities entirely and simply counts the number of positive features for each option, choosing the one with the higher count (with ties broken randomly or via a secondary mechanism). Alternatively, consider a 'Lexicographic Semi-Order' model, which operates like TTB but assumes a discrimination threshold (features only discriminate if the difference in their values exceeds a certain epsilon, though here features are binary so this might reduce to a probabilistic TTB). Tallying is a standard baseline that contrasts with both TTB (which uses validities but ignores most cues) and WADD (which uses validities and integrates all cues)."
}
```

## Usage

```json
{
  "prompt_token_count": 14243,
  "candidates_token_count": 399,
  "total_token_count": 15448
}
```
