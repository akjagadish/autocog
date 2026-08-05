# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_6") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_6" (THEORY 2 below). Justify your choice.


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


## THEORY 2 — pi_6
Tallying (Equal Weights) heuristic: Decision makers ignore cue validities entirely and simply count the number of positive features for each option. They choose the option with the higher tally (i.e., the greatest number of positive cues). This represents a fast-and-frugal compensatory strategy where all cues are weighted equally, minimizing cognitive effort while still integrating all available features. Response noise is incorporated via a softmax function over the tallies, alongside a uniform lapse rate for random errors.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    a, b = stim[0], stim[1]
    
    # Tallying: count the number of positive features for each option
    scores = np.array([np.sum(a), np.sum(b)], dtype=float)
    
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
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 4: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  trial 5: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 6: A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 7: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 8: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Rationale:** This design systematically contrasts Take-The-Best (TTB) with Tallying (Equal Weights). TTB relies on a lexicographic search based on cue validities, completely ignoring the total number of positive features if a high-validity cue discriminates. Tallying, conversely, ignores cue validities entirely and simply sums the positive features. We use five features with a clear validity gradient. Critical trials pit the single highest-validity discriminating feature against the sheer number of remaining lower-validity features. In these adversarial trials, TTB chooses the option favored by the top discriminating cue, while Tallying chooses the option with the higher total count of positive features. We also include trials where Tallying predicts a tie but TTB does not, and trials where both models agree, to robustly estimate response noise and lapse rates.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.17128773875539124, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.17450682852807284, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.8195, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.835625, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 0))|0': 0.8177935943060498, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 0))|1': 0.8246013667425968, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.1654210264075735, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.18455743879472694, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.17528373266078184, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.1673286991062562, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 0))|0': 0.16666666666666666, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 0))|1': 0.15737298636926889, '((0, 0, 0, 1, 1), (1, 1, 1, 0, 0))|0': 0.8265107212475633, '((0, 0, 0, 1, 1), (1, 1, 1, 0, 0))|1': 0.8178294573643411, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 1))|0': 0.8279932546374368, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 1))|1': 0.8224852071005917}
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
- Predicted under pi_3 (simulated): 0.0003 (var=0.0003)
- Predicted under pi_6 (simulated): 0.1371 (var=0.0024)
- Observed on real data: 0.0015 (var=0.0002)

## EXPERIMENT 2 (proposed by pi_6)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=9):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  trial 4: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 5: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 6: A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 7: A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  trial 8: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 9: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** This design systematically contrasts Tallying (Equal Weights) with Take-The-Best (TTB). Tallying ignores cue validities and simply counts the number of positive features, choosing the option with the higher count. TTB relies on a lexicographic search, choosing the option favored by the single highest-validity discriminating cue while ignoring all remaining features. By using five features with a clear validity gradient, we construct critical trials where the single best discriminating feature favors one option, but the sheer count of remaining lower-validity features favors the other. In these adversarial trials, TTB and Tallying make opposite predictions. We also include trials where Tallying predicts a tie while TTB does not, and congruent trials where both models agree, to robustly estimate response noise and lapse rates for each strategy.

**Computed schedule:** 9 unique pairs × 10 reps = 90 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 0, 0, 1, 1), (0, 0, 1, 0, 0))|0': 0.17307692307692307, '((0, 0, 0, 1, 1), (0, 0, 1, 0, 0))|1': 0.17560321715817695, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.8544078361531612, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.8315649867374005, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.803395889186774, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.834662413609782, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.17767503302509907, '((1, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.16218034993270525, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.8561320754716981, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.873249299719888, '((1, 0, 1, 0, 0), (0, 1, 0, 0, 1))|0': 0.49464524765729584, '((1, 0, 1, 0, 0), (0, 1, 0, 0, 1))|1': 0.49734395750332006, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 1))|0': 0.8403237674760854, '((0, 1, 0, 1, 0), (1, 0, 1, 0, 1))|1': 0.8202315661182206, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.14513981358189082, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.14152202937249667, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|0': 0.1257995735607676, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|1': 0.12366603892027621}
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
- Predicted under pi_3 (simulated): 0.1862 (var=0.0056)
- Predicted under pi_6 (simulated): 0.0008 (var=0.0003)
- Observed on real data: 0.1819 (var=0.0022)

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
**Predicted under pi_6:** 0.0015 (var=0.0002)

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
**Predicted under pi_6:** 0.0370 (var=0.0008)

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
**Predicted under pi_6:** 0.1655 (var=0.0035)

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
**Predicted under pi_6:** 0.0177 (var=0.0006)

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
**Predicted under pi_6:** 0.1934 (var=0.0053)

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
**Predicted under pi_6:** 0.0258 (var=0.0005)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]

**Metric**
```python
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

```

**Observed (real) value:** 0.0017 (var=0.0001)
**Predicted under pi_3:** 0.0011 (var=0.0002)
**Predicted under pi_6:** 0.1715 (var=0.0032)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
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

```

**Observed (real) value:** 0.2047 (var=0.0037)
**Predicted under pi_3:** 0.1799 (var=0.0045)
**Predicted under pi_6:** 0.0179 (var=0.0003)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across almost all experiments, the observed data strongly aligns with the predictions of THEORY 1 (Take-The-Best). When the metric measures divergence from TTB (e.g., Exps 1, 5, 7, 9), the observed divergence is near zero, matching TTB's self-prediction. When the metric measures divergence from Tallying (e.g., Exps 2, 3, 6, 10), the observed divergence is high and closely matches TTB's predicted divergence from Tallying. This consistently indicates that subjects rely heavily on cue validities rather than simply counting positive features. THEORY 2 (Tallying) is degenerate for this dataset.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace Tallying with a Weighted Additive (WADD) theory. Since subjects clearly use cue validities, a stronger competitor to the non-compensatory Take-The-Best model is a compensatory model that integrates all features but weights them proportionally to their validities. In WADD, the score for each option is the sum of its features multiplied by their respective validities (or log-odds), followed by a softmax choice rule and a lapse rate."
}
```

## Usage

```json
{
  "prompt_token_count": 17522,
  "candidates_token_count": 279,
  "total_token_count": 18870
}
```
