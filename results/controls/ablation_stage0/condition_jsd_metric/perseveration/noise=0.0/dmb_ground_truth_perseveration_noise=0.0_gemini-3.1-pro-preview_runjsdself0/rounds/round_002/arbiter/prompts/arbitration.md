# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
People make choices by computing a weighted sum of the features for each option (the Weighted Additive, or WADD, heuristic). Unlike Take The Best or Tallying, WADD scales the contribution of each feature by its validity. Furthermore, features are processed as bipolar evidence: the presence of a feature adds to the option's value proportionally to its validity, while its absence actively penalizes the option. The resulting option scores are translated into choice probabilities via a softmax function, with an independent lapse rate accounting for random guessing.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    # WADD (Weighted Additive) heuristic.
    # Stimulus is the pair of option feature vectors for the current
    # trial: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    val = np.asarray(parameters["validities"], dtype=float)
    
    # Center the stimulus features to -1 and 1 so absence of a feature penalizes
    stim_centered = stim * 2.0 - 1.0
    
    # Compute the weighted sum of features for each option.
    # The weights are directly proportional to the cue validities.
    scores = np.dot(stim_centered, val)

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_4
Decision-makers use the Take-The-Best (TTB) heuristic, searching through features in descending order of their validities. The search stops at the first feature that discriminates between the options, and the option favored by that feature is chosen. If no features discriminate, the choice is a random guess. To account for behavioral noise without parameter redundancy, deviations from the deterministic TTB rule are modeled using a single lapse rate parameter (epsilon), replacing the redundant softmax temperature found in prior TTB instantiations.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    val = np.asarray(parameters['validities'], dtype=float)
    
    cue_order = np.argsort(-val, kind='stable')
    a, b = stim[0], stim[1]
    
    p_core = np.array([0.5, 0.5])
    for idx in cue_order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters['epsilon'])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    p = np.asarray(probs, dtype=np.float64)
    p /= p.sum()
    return int(np.random.choice(len(p), p=p))

## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 4: A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  trial 5: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 6: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 7: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 8: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 9: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 10: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Rationale:** This design quantitatively dissociates the Weighted Additive (WADD) heuristic from Take-The-Best (TTB) using 5 features. TTB relies solely on the most valid discriminating feature, making deterministic predictions regardless of the opposing evidence. In contrast, WADD integrates all features weighted by their validities, with the absence of a feature actively penalizing the option. By constructing trials where the single highest-validity feature points to one option while multiple lower-validity features point to the other, we create opposing predictions (e.g., TTB chooses A, WADD chooses B). Additionally, by varying the net validity difference across trials where both heuristics agree, we can detect WADD's graded choice probabilities (via softmax) versus TTB's constant confidence level.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.8727025187202179, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.8732737611697806, '((1, 0, 1, 0, 1), (0, 1, 0, 1, 0))|0': 0.13749114103472715, '((1, 0, 1, 0, 1), (0, 1, 0, 1, 0))|1': 0.15267947421638017, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 1))|0': 0.8467741935483871, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 1))|1': 0.8539603960396039, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 0))|0': 0.12545018007202882, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 0))|1': 0.14216634429400388, '((0, 0, 0, 0, 1), (1, 1, 1, 1, 0))|0': 0.8807600950118765, '((0, 0, 0, 0, 1), (1, 1, 1, 1, 0))|1': 0.8521008403361344, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|0': 0.15547263681592038, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|1': 0.1371308016877637, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.8691049085659288, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.8585189644792294, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|0': 0.11428571428571428, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|1': 0.13272727272727272, '((1, 1, 1, 1, 0), (0, 0, 0, 0, 1))|0': 0.1178082191780822, '((1, 1, 1, 1, 0), (0, 0, 0, 0, 1))|1': 0.15080645161290324, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.8625877632898696, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.8526130358191427}
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
- Predicted under pi_3 (simulated): 0.0008 (var=0.0001)
- Predicted under pi_4 (simulated): 0.0913 (var=0.0016)
- Observed on real data: 0.2658 (var=0.0000)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=6):** [0.95, 0.85, 0.75, 0.65, 0.55, 0.5]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  trial 5: A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  trial 6: A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  trial 7: A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  trial 8: A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  trial 9: A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  trial 10: A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0, 0]

**Rationale:** This design isolates Take-The-Best (TTB) from the Weighted Additive (WADD) heuristic by creating opposing predictions and exploiting WADD's graded sensitivity to the magnitude of evidence. Using 6 features with a wide spread of validities, we construct conflict trials where TTB's strict non-compensatory reliance on the most valid discriminating cue predicts one choice, while WADD's compensatory integration of all features predicts the opposite. Furthermore, we include pairs where both heuristics agree on the direction but WADD predicts varying choice probabilities due to different net score differences, whereas TTB predicts a constant confidence level (1-epsilon) since it only considers the first discriminating cue.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1))|0': 0.22847522847522847, '((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1))|1': 0.30434782608695654, '((1, 0, 1, 0, 0, 0), (0, 1, 0, 1, 0, 0))|0': 0.2122549019607843, '((1, 0, 1, 0, 0, 0), (0, 1, 0, 1, 0, 0))|1': 0.33484848484848484, '((1, 1, 1, 1, 1, 1), (0, 0, 0, 0, 0, 0))|0': 0.22483221476510068, '((1, 1, 1, 1, 1, 1), (0, 0, 0, 0, 0, 0))|1': 0.30781758957654726, '((1, 0, 1, 0, 0, 0), (0, 1, 0, 1, 1, 1))|0': 0.20794958797867183, '((1, 0, 1, 0, 0, 0), (0, 1, 0, 1, 1, 1))|1': 0.3108320251177394, '((1, 0, 0, 0, 1, 0), (0, 1, 1, 0, 0, 0))|0': 0.19950980392156864, '((1, 0, 0, 0, 1, 0), (0, 1, 1, 0, 0, 0))|1': 0.3303030303030303, '((1, 1, 0, 0, 0, 0), (0, 0, 1, 1, 1, 1))|0': 0.2198751800288046, '((1, 1, 0, 0, 0, 0), (0, 0, 1, 1, 1, 1))|1': 0.3338735818476499, '((1, 0, 0, 1, 0, 0), (0, 1, 1, 0, 1, 1))|0': 0.21141439205955334, '((1, 0, 0, 1, 0, 0), (0, 1, 1, 0, 1, 1))|1': 0.33138686131386863, '((0, 0, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1))|0': 0.20784883720930233, '((0, 0, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1))|1': 0.3333333333333333, '((1, 0, 0, 0, 0, 0), (0, 1, 1, 1, 1, 1))|0': 0.2015376166941241, '((1, 0, 0, 0, 0, 0), (0, 1, 1, 1, 1, 1))|1': 0.3229706390328152, '((0, 1, 0, 0, 0, 0), (0, 0, 1, 1, 1, 1))|0': 0.19639376218323587, '((0, 1, 0, 0, 0, 0), (0, 0, 1, 1, 1, 1))|1': 0.32098765432098764}
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
- Predicted under pi_3 (simulated): 0.1229 (var=0.0018)
- Predicted under pi_4 (simulated): 0.0007 (var=0.0002)
- Observed on real data: 0.2074 (var=0.0151)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
P_REF = {'((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.12373831775700934, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.16864864864864865, '((0, 0, 1, 1, 1), (1, 0, 0, 0, 0))|0': 0.8707455429497569, '((0, 0, 1, 1, 1), (1, 0, 0, 0, 0))|1': 0.842756183745583, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.13971830985915493, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.13315068493150686, '((0, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.14070162202942285, '((0, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.15911485774499473, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.1434994379917572, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.1439312567132116, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 0))|0': 0.862147406733394, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 0))|1': 0.8509272467902995, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.14093959731543623, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.15824175824175823, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.12565812565812565, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.17738359201773837}
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

**Observed (real) value:** 0.2326 (var=0.0093)
**Predicted under pi_3:** 0.2387 (var=0.0045)
**Predicted under pi_4:** 0.0071 (var=0.0003)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
P_REF = {'((0, 0, 0, 1, 1), (0, 0, 1, 0, 0))|0': 0.15132924335378323, '((0, 0, 0, 1, 1), (0, 0, 1, 0, 0))|1': 0.15049226441631505, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.8864696734059098, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.8513513513513513, '((1, 1, 0, 1, 1), (1, 1, 1, 0, 0))|0': 0.1476923076923077, '((1, 1, 0, 1, 1), (1, 1, 1, 0, 0))|1': 0.1409090909090909, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 0))|0': 0.5088640840446487, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 0))|1': 0.5267958950969214, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 1))|0': 0.14424173318129987, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 1))|1': 0.16408668730650156, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.8602006688963211, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.8486187845303867, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.8741418764302059, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.8512396694214877, '((1, 0, 0, 1, 0), (0, 1, 1, 0, 0))|0': 0.5034550839091807, '((1, 0, 0, 1, 0), (0, 1, 1, 0, 0))|1': 0.4830569574621485, '((0, 1, 0, 1, 1), (1, 0, 0, 0, 0))|0': 0.12566641279512566, '((0, 1, 0, 1, 1), (1, 0, 0, 0, 0))|1': 0.15547378104875806, '((1, 1, 0, 0, 1), (1, 0, 1, 1, 0))|0': 0.504950495049505, '((1, 1, 0, 0, 1), (1, 0, 1, 1, 0))|1': 0.49954001839926404, '((1, 0, 1, 1, 0), (1, 1, 0, 0, 1))|0': 0.4824976348155156, '((1, 0, 1, 1, 0), (1, 1, 0, 0, 1))|1': 0.47282204020848845, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.13087248322147652, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.13186813186813187}
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

**Observed (real) value:** 0.2312 (var=0.0009)
**Predicted under pi_3:** 0.0006 (var=0.0001)
**Predicted under pi_4:** 0.1462 (var=0.0111)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]

**Metric**
```python
P_REF = {'((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.8303078137332282, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.8450802512212142, '((0, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.8291666666666667, '((0, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.819047619047619, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.13747054202670855, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.13043478260869565, '((0, 0, 1, 1, 0), (1, 1, 0, 0, 1))|0': 0.8546296296296296, '((0, 0, 1, 1, 0), (1, 1, 0, 0, 1))|1': 0.8617283950617284, '((0, 1, 0, 0, 0), (1, 0, 0, 0, 0))|0': 0.7611386138613861, '((0, 1, 0, 0, 0), (1, 0, 0, 0, 0))|1': 0.7583025830258303, '((1, 0, 0, 0, 0), (0, 1, 0, 0, 0))|0': 0.2328042328042328, '((1, 0, 0, 0, 0), (0, 1, 0, 0, 0))|1': 0.22727272727272727, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.16793168880455409, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.17618469015795868, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|0': 0.15034965034965034, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|1': 0.13228346456692913, '((1, 0, 1, 1, 0), (0, 1, 0, 0, 1))|0': 0.13085234093637454, '((1, 0, 1, 1, 0), (0, 1, 0, 0, 1))|1': 0.1769825918762089, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.8602693602693603, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.8611111111111112}
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

**Observed (real) value:** 0.2566 (var=0.0000)
**Predicted under pi_3:** 0.0008 (var=0.0001)
**Predicted under pi_4:** 0.0276 (var=0.0003)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0]

**Metric**
```python
P_REF = {'((1, 1, 0, 0, 0, 0), (0, 0, 1, 0, 1, 1))|0': 0.8378978534418949, '((1, 1, 0, 0, 0, 0), (0, 0, 1, 0, 1, 1))|1': 0.8474877723432637, '((0, 0, 0, 1, 0, 0), (1, 1, 1, 0, 0, 0))|0': 0.8636604774535809, '((0, 0, 0, 1, 0, 0), (1, 1, 1, 0, 0, 0))|1': 0.8693877551020408, '((0, 0, 0, 1, 1, 1), (1, 1, 0, 0, 0, 0))|0': 0.15860517435320584, '((0, 0, 0, 1, 1, 1), (1, 1, 0, 0, 0, 0))|1': 0.15806805708013172, '((1, 1, 0, 0, 0, 0), (0, 0, 0, 1, 1, 1))|0': 0.8434393638170974, '((1, 1, 0, 0, 0, 0), (0, 0, 0, 1, 1, 1))|1': 0.8457178841309824, '((0, 0, 1, 1, 0, 0), (1, 1, 0, 0, 0, 0))|0': 0.5163297045101088, '((0, 0, 1, 1, 0, 0), (1, 1, 0, 0, 0, 0))|1': 0.5230400957510473, '((1, 1, 0, 0, 0, 0), (0, 0, 1, 1, 0, 0))|0': 0.5212169735788631, '((1, 1, 0, 0, 0, 0), (0, 0, 1, 1, 0, 0))|1': 0.49829351535836175, '((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 0, 0))|0': 0.1387252276379218, '((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 0, 0))|1': 0.13791113675706868, '((0, 0, 1, 0, 1, 1), (1, 1, 0, 0, 0, 0))|0': 0.14910262310170272, '((0, 0, 1, 0, 1, 1), (1, 1, 0, 0, 0, 0))|1': 0.16398037841625787}
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

**Observed (real) value:** 0.2497 (var=0.0000)
**Predicted under pi_3:** 0.0874 (var=0.0014)
**Predicted under pi_4:** 0.1108 (var=0.0041)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed Jensen-Shannon divergence (JSD) between the real data and the reference probabilities is consistently high (ranging from 0.20 to 0.26). In contrast, the simulated predictions from both Theory 1 (WADD) and Theory 2 (TTB) yield much lower JSD values (often close to 0 for their own proposed experiments). This massive gap between simulated and observed metrics indicates that neither a purely compensatory, validity-weighted integration (WADD) nor a strictly non-compensatory, lexicographic search (TTB) accurately captures human decision-making in this domain. Human behavior likely involves a different mechanism, such as ignoring validities entirely (Tallying), or employing a mixture of strategies depending on the difficulty of the trial.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a brand-new theory based on 'Tallying' (or equal-weight integration). In this theory, subjects ignore the specific expert validities and simply count the number of positive features (or net positive features) for each option. The choice probabilities are then derived via a softmax function over these unweighted tally scores. This differs from WADD (which scales by validity) and TTB (which stops at the first discriminating feature), potentially capturing the observed data's divergence from both existing models."
}
```

## Usage

```json
{
  "prompt_token_count": 14107,
  "candidates_token_count": 304,
  "total_token_count": 15228
}
```
