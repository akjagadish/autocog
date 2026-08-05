# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_2") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2" (THEORY 2 below). Justify your choice.


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


## THEORY 2 — pi_2
People compare two options by computing, for each option, a weighted sum of its feature values, where each feature is weighted by its subjective validity (or importance). The option with the higher weighted sum is chosen. WADD is the compensatory benchmark against which one-reason heuristics like Take The Best are contrasted: a large deficit on a high-validity cue can be compensated by a sufficiently strong advantage on lower-validity cues, so no single feature is ever decisive on its own. Unlike Tallying, WADD uses cardinal feature magnitudes and weights them by validity, so it exploits both the sign and the size of each feature-wise comparison as well as inter-cue differences in informativeness. Unlike Equal-Weight, weights differ across features. Behavior is invariant to a shared affine rescaling across options but scales linearly with per-feature weight. When the two weighted sums are equal the model has no basis for preference and the learner must guess. Response noise enters through a softmax over the two weighted sums with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Weighted Additive rule (Payne, Bettman & Johnson
    # 1993). Stimulus is the pair of option feature vectors for the
    # current trial: array-like of shape (2, n_features), row 0 =
    # option A, row 1 = option B. Each option's score is the dot
    # product of its feature vector with the (subjective) validity
    # weights. History is ignored: the choice depends only on the
    # current stimulus.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    validities = np.asarray(parameters["validities"], dtype=float)
    w = np.asarray(parameters["weights"], dtype=float)
    if w.shape[0] != n_features:
        raise ValueError(
            f"weights length {w.shape[0]} != n_features {n_features}."
        )

    # Weighted sum per option (dot product with per-feature weights).
    scores = stim @ (validities * w)

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Uniform lapse blended into the softmax (standard choice-with-lapse
    # formulation; epsilon=0.5 yields equiprobable options, matching
    # the paper's maximum-noise condition).
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 6: A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 7: A=[0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 8: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate Take-The-Best (TTB) from the Weighted Additive (WADD) model, we exploit TTB's strict non-compensatory nature versus WADD's compensatory weighting. We use five features with linearly decreasing validities. The critical trials are designed such that the single highest-validity discriminating feature favors one option (which TTB will categorically choose), while the sum of multiple lower-validity discriminating features strongly favors the other option (which WADD will choose, provided the cumulative weight overcomes the single best cue). We also include trials where both models agree to serve as a baseline for response noise.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
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


### RESULTS
- Predicted under pi_3 (simulated): 0.0004 (var=0.0002)
- Predicted under pi_2 (simulated): 0.1149 (var=0.0036)
- Observed on real data: 0.0045 (var=0.0002)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.75, 0.7, 0.6]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 4: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 5: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 6: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 7: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 8: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Rationale:** To quantitatively dissociate the compensatory Weighted Additive (WADD) model from the non-compensatory Take-The-Best (TTB) heuristic, we use a 5-feature design with a steep but surmountable validity gradient. The critical trials pit the single highest-validity feature against a coalition of multiple lower-validity features. In these adversarial trials, TTB's lexicographic stopping rule forces it to choose the option favored by the single best discriminating feature, ignoring the rest. WADD, however, integrates all features and will choose the opposite option because the sum of the lower-validity features outweighs the single best feature. We also include congruent trials where both models agree, and partially conflicting trials where the coalition is not strong enough to overcome the best feature, providing a precise measure of the compensatory threshold and response noise.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
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


### RESULTS
- Predicted under pi_3 (simulated): 0.1342 (var=0.0035)
- Predicted under pi_2 (simulated): 0.0018 (var=0.0015)
- Observed on real data: 0.1288 (var=0.0025)

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
**Predicted under pi_2:** 0.0221 (var=0.0020)

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
**Predicted under pi_2:** 0.0008 (var=0.0019)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, Theory 1 (Take-The-Best) consistently captures the observed behavior much better than Theory 2 (Weighted Additive). In Experiment 1, the observed data matches the TTB-generated reference almost perfectly (JSD=0.0045), which TTB predicts accurately. In Experiments 2, 3, and 4, the references were likely generated under WADD, and the real data showed a large divergence from these references (JSDs of 0.1288, 0.1100, and 0.0623). In every case, TTB correctly predicted this large divergence, while WADD incorrectly predicted a near-zero JSD. This indicates that subjects are overwhelmingly using a non-compensatory heuristic like TTB rather than compensatory weighted addition.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Since Weighted Additive (WADD) completely fails to capture the non-compensatory nature of the subjects' choices, replace it with a new theory that offers a more plausible alternative heuristic. A good candidate is 'Tallying' (Equal-Weight heuristic), where subjects simply count the number of positive features for each option ignoring validities, or a 'Two-Stage' model where subjects try TTB first but fall back to tallying if the validity difference between cues is too small. This will provide a stricter, more realistic bounds-on-rationality competitor to TTB."
}
```

## Usage

```json
{
  "prompt_token_count": 8964,
  "candidates_token_count": 330,
  "total_token_count": 10111
}
```
