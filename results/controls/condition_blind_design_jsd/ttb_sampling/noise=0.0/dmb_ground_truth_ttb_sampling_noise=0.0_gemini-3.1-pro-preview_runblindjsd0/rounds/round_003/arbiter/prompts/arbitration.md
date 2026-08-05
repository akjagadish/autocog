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
Take-The-Best (TTB) heuristic: Decision-makers evaluate options using a non-compensatory, rank-based approach. They first rank the available features by their validity (descending). They then sequentially compare the options on these features, stopping at the first feature that discriminates between them (i.e., one option has a higher value than the other). The option favored by this discriminating feature is chosen, and all remaining features are completely ignored. If no features discriminate between the options, the decision-maker resorts to a random guess.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Rank features by validity in descending order.
    # Using mergesort for a stable sort in case of ties.
    order = np.argsort(-validities, kind='mergesort')
    
    a, b = stim[0], stim[1]
    
    # Default to guessing if no feature discriminates
    p_core = np.array([0.5, 0.5])
    
    # Sequentially check features according to their validity ranking
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    
    # Blend the deterministic choice (or guess) with the lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_5
Weighted Additive (WADD) Strategy with Bounded Weights and Expanded Temperature: Decision-makers evaluate options using a compensatory approach where all available features are integrated. Each feature is weighted by its log-odds validity, reflecting its normative diagnostic value. The subjective weight of a cue is bounded (equivalent to clipping validity at 0.05 and 0.95) to prevent extreme over-weighting. The decision-maker sums the bounded weighted feature values for each option and translates the resulting scores into choice probabilities via a softmax function, with a wide temperature range allowing for highly deterministic behavior when required.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Clip validities to avoid extreme log-odds values and division by zero
    v = np.clip(validities, 0.05, 0.95)
    # Compute log-odds weights for each feature
    w = np.log(v / (1.0 - v))
    
    a, b = stim[0], stim[1]
    
    # Calculate the weighted sum of features for each option
    score_a = np.sum(w * a)
    score_b = np.sum(w * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Translate scores to probabilities using a numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate lapse rate (random guessing)
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=4):** [0.95, 0.84, 0.8, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  trial 2: A=[1, 0, 0, 1]  B=[0, 0, 0, 1]
  trial 3: A=[0, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 4: A=[0, 0, 0, 0]  B=[1, 1, 1, 1]
  trial 5: A=[1, 1, 0, 1]  B=[1, 0, 1, 1]
  trial 6: A=[0, 1, 0, 0]  B=[1, 1, 1, 1]
  trial 7: A=[1, 1, 1, 1]  B=[1, 1, 0, 0]
  trial 8: A=[1, 0, 1, 0]  B=[0, 0, 1, 0]
  trial 9: A=[1, 0, 1, 0]  B=[0, 1, 1, 0]
  trial 10: A=[1, 0, 0, 0]  B=[1, 1, 1, 1]
  trial 11: A=[1, 1, 0, 1]  B=[1, 1, 1, 1]
  trial 12: A=[0, 1, 0, 1]  B=[1, 1, 1, 0]
  trial 13: A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  trial 14: A=[0, 1, 1, 1]  B=[0, 1, 0, 0]
  trial 15: A=[1, 0, 1, 1]  B=[1, 1, 1, 1]
  trial 16: A=[0, 0, 1, 1]  B=[1, 0, 1, 1]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 1, 1, 1), (0, 1, 0, 0))|0': 0.11620111731843576, '((0, 1, 1, 1), (0, 1, 0, 0))|1': 0.1292817679558011, '((1, 1, 0, 1), (1, 1, 1, 1))|0': 0.8507462686567164, '((1, 1, 0, 1), (1, 1, 1, 1))|1': 0.8610067618332081, '((0, 0, 1, 1), (1, 1, 1, 1))|0': 0.8886389201349831, '((0, 0, 1, 1), (1, 1, 1, 1))|1': 0.8682766190998902, '((0, 1, 1, 1), (0, 0, 0, 0))|0': 0.12312312312312312, '((0, 1, 1, 1), (0, 0, 0, 0))|1': 0.11728395061728394, '((0, 1, 0, 0), (1, 1, 1, 1))|0': 0.8845598845598845, '((0, 1, 0, 0), (1, 1, 1, 1))|1': 0.8735320686540199, '((1, 1, 1, 1), (1, 1, 0, 0))|0': 0.12576687116564417, '((1, 1, 1, 1), (1, 1, 0, 0))|1': 0.13066202090592335, '((1, 0, 0, 0), (1, 1, 1, 1))|0': 0.8780795957043588, '((1, 0, 0, 0), (1, 1, 1, 1))|1': 0.8341013824884793, '((1, 0, 1, 0), (0, 0, 1, 0))|0': 0.14157303370786517, '((1, 0, 1, 0), (0, 0, 1, 0))|1': 0.11881918819188192, '((1, 0, 0, 1), (0, 0, 0, 1))|0': 0.11144578313253012, '((1, 0, 0, 1), (0, 0, 0, 1))|1': 0.13204225352112675, '((1, 0, 1, 0), (0, 1, 1, 0))|0': 0.12128146453089245, '((1, 0, 1, 0), (0, 1, 1, 0))|1': 0.1485623003194888, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8737864077669902, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8515742128935532, '((1, 0, 1, 1), (1, 1, 1, 1))|0': 0.8766140602582496, '((1, 0, 1, 1), (1, 1, 1, 1))|1': 0.8730734360834089, '((1, 1, 0, 1), (1, 0, 1, 1))|0': 0.13449023861171366, '((1, 1, 0, 1), (1, 0, 1, 1))|1': 0.1082004555808656, '((0, 0, 1, 1), (1, 0, 1, 1))|0': 0.8541973490427098, '((0, 0, 1, 1), (1, 0, 1, 1))|1': 0.8911685994647636, '((0, 0, 0, 0), (1, 1, 1, 1))|0': 0.8811659192825112, '((0, 0, 0, 0), (1, 1, 1, 1))|1': 0.8854625550660793, '((0, 1, 0, 1), (1, 1, 1, 0))|0': 0.8666666666666667, '((0, 1, 0, 1), (1, 1, 1, 0))|1': 0.8737777777777778}
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
- Predicted under pi_5 (simulated): 0.0009 (var=0.0000)
- Observed on real data: 0.0027 (var=0.0003)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=4):** [0.95, 0.72, 0.67, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[1, 0, 0, 0]  B=[1, 0, 1, 1]
  trial 2: A=[0, 0, 1, 1]  B=[0, 1, 1, 1]
  trial 3: A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  trial 4: A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  trial 5: A=[1, 0, 0, 1]  B=[0, 1, 1, 1]
  trial 6: A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  trial 7: A=[0, 1, 0, 0]  B=[0, 0, 0, 0]
  trial 8: A=[0, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 9: A=[0, 1, 1, 1]  B=[1, 1, 0, 0]
  trial 10: A=[0, 1, 0, 1]  B=[1, 1, 0, 1]
  trial 11: A=[0, 1, 0, 1]  B=[0, 0, 1, 0]
  trial 12: A=[0, 0, 1, 0]  B=[1, 0, 0, 0]
  trial 13: A=[1, 0, 1, 1]  B=[0, 0, 1, 0]
  trial 14: A=[1, 1, 0, 0]  B=[1, 1, 1, 0]
  trial 15: A=[1, 0, 0, 0]  B=[1, 0, 0, 1]
  trial 16: A=[1, 0, 0, 0]  B=[1, 1, 0, 1]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 0, 0, 0), (1, 0, 0, 1))|0': 0.834070796460177, '((1, 0, 0, 0), (1, 0, 0, 1))|1': 0.8471810089020771, '((1, 0, 0, 0), (1, 1, 0, 1))|0': 0.8593406593406593, '((1, 0, 0, 0), (1, 1, 0, 1))|1': 0.8797752808988764, '((1, 0, 1, 1), (0, 0, 1, 0))|0': 0.1406926406926407, '((1, 0, 1, 1), (0, 0, 1, 0))|1': 0.12705530642750373, '((1, 1, 0, 0), (1, 1, 1, 0))|0': 0.8793893129770992, '((1, 1, 0, 0), (1, 1, 1, 0))|1': 0.8751091703056768, '((0, 1, 0, 0), (0, 0, 0, 0))|0': 0.1224122412241224, '((0, 1, 0, 0), (0, 0, 0, 0))|1': 0.11320754716981132, '((1, 0, 0, 1), (1, 0, 0, 0))|0': 0.14200743494423793, '((1, 0, 0, 1), (1, 0, 0, 0))|1': 0.15824175824175823, '((1, 0, 0, 0), (0, 1, 1, 0))|0': 0.12935883014623173, '((1, 0, 0, 0), (0, 1, 1, 0))|1': 0.1394072447859495, '((0, 0, 1, 0), (1, 0, 0, 0))|0': 0.8685612788632326, '((0, 0, 1, 0), (1, 0, 0, 0))|1': 0.8590504451038575, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8711111111111111, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8773333333333333, '((1, 0, 0, 1), (0, 1, 1, 1))|0': 0.1108695652173913, '((1, 0, 0, 1), (0, 1, 1, 1))|1': 0.1159090909090909, '((0, 1, 1, 1), (0, 0, 0, 0))|0': 0.1280120481927711, '((0, 1, 1, 1), (0, 0, 0, 0))|1': 0.11179577464788733, '((0, 1, 0, 1), (0, 0, 1, 0))|0': 0.16544655929721816, '((0, 1, 0, 1), (0, 0, 1, 0))|1': 0.12891674127126232, '((1, 0, 0, 0), (1, 0, 1, 1))|0': 0.8665644171779141, '((1, 0, 0, 0), (1, 0, 1, 1))|1': 0.8808962264150944, '((0, 1, 0, 1), (1, 1, 0, 1))|0': 0.8539493293591655, '((0, 1, 0, 1), (1, 1, 0, 1))|1': 0.895482728077945, '((0, 0, 1, 1), (0, 1, 1, 1))|0': 0.8699007717750827, '((0, 0, 1, 1), (0, 1, 1, 1))|1': 0.8768197088465846, '((0, 1, 1, 1), (1, 1, 0, 0))|0': 0.8801331853496115, '((0, 1, 1, 1), (1, 1, 0, 0))|1': 0.8798665183537263}
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
- Predicted under pi_3 (simulated): 0.0010 (var=0.0001)
- Predicted under pi_5 (simulated): 0.0012 (var=0.0002)
- Observed on real data: 0.0026 (var=0.0002)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 1, 0, 0]  B=[1, 1, 1, 0]
  A=[1, 1, 1, 0]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 0, 1, 0]
  A=[0, 0, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 0, 1, 1]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 0]  B=[1, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 0, 1]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 1, 1]
  A=[0, 0, 0, 1]  B=[1, 0, 1, 1]

**Metric**
```python
P_REF = {'((1, 1, 1, 0), (0, 1, 0, 0))|0': 0.13670886075949368, '((1, 1, 1, 0), (0, 1, 0, 0))|1': 0.11287128712871287, '((0, 1, 1, 1), (0, 0, 0, 0))|0': 0.12745098039215685, '((0, 1, 1, 1), (0, 0, 0, 0))|1': 0.11979166666666667, '((1, 0, 0, 1), (0, 1, 1, 1))|0': 0.8440779610194903, '((1, 0, 0, 1), (0, 1, 1, 1))|1': 0.8649602824360106, '((1, 0, 0, 1), (1, 1, 1, 0))|0': 0.8597081930415263, '((1, 0, 0, 1), (1, 1, 1, 0))|1': 0.8404840484048405, '((1, 1, 1, 0), (1, 0, 1, 0))|0': 0.18133333333333335, '((1, 1, 1, 0), (1, 0, 1, 0))|1': 0.13894736842105262, '((0, 1, 0, 0), (1, 1, 0, 1))|0': 0.856301531213192, '((0, 1, 0, 0), (1, 1, 0, 1))|1': 0.8494623655913979, '((0, 1, 0, 0), (1, 0, 0, 1))|0': 0.8326180257510729, '((0, 1, 0, 0), (1, 0, 0, 1))|1': 0.8746594005449592, '((1, 0, 1, 0), (0, 0, 0, 1))|0': 0.1670235546038544, '((1, 0, 1, 0), (0, 0, 0, 1))|1': 0.14103525881470366, '((1, 0, 1, 1), (0, 0, 1, 1))|0': 0.19970845481049562, '((1, 0, 1, 1), (0, 0, 1, 1))|1': 0.1490125673249551, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8724727838258165, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8755401901469317, '((1, 1, 0, 1), (0, 0, 1, 1))|0': 0.14446952595936793, '((1, 1, 0, 1), (0, 0, 1, 1))|1': 0.14660831509846828, '((0, 0, 1, 1), (0, 1, 1, 1))|0': 0.8440233236151603, '((0, 0, 1, 1), (0, 1, 1, 1))|1': 0.86983842010772, '((1, 1, 0, 0), (1, 1, 1, 0))|0': 0.752851711026616, '((1, 1, 0, 0), (1, 1, 1, 0))|1': 0.8666232921275211, '((1, 0, 0, 0), (1, 1, 0, 0))|0': 0.8525730180806675, '((1, 0, 0, 0), (1, 1, 0, 0))|1': 0.8287292817679558, '((0, 0, 0, 1), (1, 0, 1, 1))|0': 0.8569463548830811, '((0, 0, 0, 1), (1, 0, 1, 1))|1': 0.8825722273998136, '((0, 0, 1, 0), (1, 0, 0, 0))|0': 0.5039370078740157, '((0, 0, 1, 0), (1, 0, 0, 0))|1': 0.5093304061470911}
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

**Observed (real) value:** 0.0251 (var=0.0002)
**Predicted under pi_3:** 0.0254 (var=0.0001)
**Predicted under pi_5:** 0.0072 (var=0.0000)

### Experiment 4
**Design**
  A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  A=[0, 0, 0, 0]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 1, 0, 1]
  A=[0, 0, 0, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 1, 1, 0]
  A=[1, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 0]  B=[1, 0, 1, 0]
  A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[1, 1, 0, 1]
  A=[1, 1, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[0, 0, 0, 1]

**Metric**
```python
P_REF = {'((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8286189683860233, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8557130942452044, '((0, 0, 0, 1), (1, 1, 1, 0))|0': 0.8488210818307905, '((0, 0, 0, 1), (1, 1, 1, 0))|1': 0.8591288229842446, '((0, 1, 0, 1), (1, 0, 1, 1))|0': 0.6946564885496184, '((0, 1, 0, 1), (1, 0, 1, 1))|1': 0.7695924764890282, '((0, 1, 0, 1), (1, 1, 0, 0))|0': 0.6170886075949367, '((0, 1, 0, 1), (1, 1, 0, 0))|1': 0.6438356164383562, '((0, 0, 1, 1), (1, 1, 1, 0))|0': 0.7890625, '((0, 0, 1, 1), (1, 1, 1, 0))|1': 0.8189655172413793, '((1, 1, 1, 1), (1, 1, 0, 0))|0': 0.18725099601593626, '((1, 1, 1, 1), (1, 1, 0, 0))|1': 0.16024653312788906, '((1, 0, 0, 0), (1, 1, 0, 1))|0': 0.8076923076923077, '((1, 0, 0, 0), (1, 1, 0, 1))|1': 0.842156862745098, '((0, 0, 1, 1), (1, 1, 1, 1))|0': 0.8343465045592705, '((0, 0, 1, 1), (1, 1, 1, 1))|1': 0.8537653239929948, '((0, 1, 0, 1), (0, 0, 0, 1))|0': 0.23655913978494625, '((0, 1, 0, 1), (0, 0, 0, 1))|1': 0.20869565217391303, '((0, 0, 1, 0), (1, 0, 1, 0))|0': 0.758364312267658, '((0, 0, 1, 0), (1, 0, 1, 0))|1': 0.8026183282980867, '((0, 1, 1, 0), (1, 1, 0, 1))|0': 0.6039119804400978, '((0, 1, 1, 0), (1, 1, 0, 1))|1': 0.7167505391804457, '((0, 0, 0, 0), (1, 0, 0, 0))|0': 0.7875354107648725, '((0, 0, 0, 0), (1, 0, 0, 0))|1': 0.7970749542961609, '((0, 1, 1, 0), (0, 0, 0, 1))|0': 0.22007042253521128, '((0, 1, 1, 0), (0, 0, 0, 1))|1': 0.23376623376623376, '((0, 0, 1, 1), (1, 1, 0, 1))|0': 0.6927710843373494, '((0, 0, 1, 1), (1, 1, 0, 1))|1': 0.7327188940092166, '((0, 0, 0, 0), (0, 0, 0, 1))|0': 0.7439862542955327, '((0, 0, 0, 0), (0, 0, 0, 1))|1': 0.7783251231527094, '((1, 1, 0, 1), (1, 0, 1, 1))|0': 0.47544642857142855, '((1, 1, 0, 1), (1, 0, 1, 1))|1': 0.5121681415929203}
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

**Observed (real) value:** 0.0105 (var=0.0002)
**Predicted under pi_3:** 0.0165 (var=0.0001)
**Predicted under pi_5:** 0.0115 (var=0.0002)

### Experiment 5
**Design**
  A=[1, 0, 1, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]
  A=[0, 0, 0, 1]  B=[0, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[0, 0, 0, 1]
  A=[1, 1, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 1, 0, 1]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 1]
  A=[1, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[0, 1, 0, 0]

**Metric**
```python
P_REF = {'((0, 1, 1, 0), (0, 1, 0, 0))|0': 0.16052060737527116, '((0, 1, 1, 0), (0, 1, 0, 0))|1': 0.1135175504107543, '((1, 1, 0, 0), (1, 1, 1, 0))|0': 0.8854824165915239, '((1, 1, 0, 0), (1, 1, 1, 0))|1': 0.8769898697539797, '((0, 0, 1, 1), (0, 0, 0, 1))|0': 0.13676148796498905, '((0, 0, 1, 1), (0, 0, 0, 1))|1': 0.11173814898419865, '((1, 1, 0, 0), (1, 1, 0, 1))|0': 0.8521816562778273, '((1, 1, 0, 0), (1, 1, 0, 1))|1': 0.8655834564254062, '((0, 1, 1, 0), (1, 0, 0, 0))|0': 0.8853046594982079, '((0, 1, 1, 0), (1, 0, 0, 0))|1': 0.8494152046783626, '((1, 1, 0, 1), (1, 0, 1, 1))|0': 0.12416851441241686, '((1, 1, 0, 1), (1, 0, 1, 1))|1': 0.1358574610244989, '((1, 1, 1, 1), (0, 0, 0, 0))|0': 0.1339754816112084, '((1, 1, 1, 1), (0, 0, 0, 0))|1': 0.12613981762917933, '((1, 0, 1, 0), (1, 1, 0, 0))|0': 0.8922651933701657, '((1, 0, 1, 0), (1, 1, 0, 0))|1': 0.8454106280193237, '((1, 0, 1, 0), (1, 0, 1, 1))|0': 0.8496932515337423, '((1, 0, 1, 0), (1, 0, 1, 1))|1': 0.8789198606271778, '((0, 1, 0, 1), (1, 0, 1, 0))|0': 0.8729281767955801, '((0, 1, 0, 1), (1, 0, 1, 0))|1': 0.8871508379888268, '((1, 1, 0, 1), (0, 0, 0, 1))|0': 0.1301969365426696, '((1, 1, 0, 1), (0, 0, 0, 1))|1': 0.1162528216704289, '((1, 0, 1, 1), (1, 0, 0, 1))|0': 0.13602391629297458, '((1, 0, 1, 1), (1, 0, 0, 1))|1': 0.1246684350132626, '((1, 1, 1, 1), (1, 1, 0, 1))|0': 0.10929368029739776, '((1, 1, 1, 1), (1, 1, 0, 1))|1': 0.17142857142857143, '((1, 1, 1, 0), (0, 1, 0, 1))|0': 0.1206896551724138, '((1, 1, 1, 0), (0, 1, 0, 1))|1': 0.13948497854077252, '((1, 0, 1, 0), (0, 1, 1, 1))|0': 0.14109742441209405, '((1, 0, 1, 0), (0, 1, 1, 1))|1': 0.11466372657111357, '((0, 0, 0, 1), (0, 1, 0, 1))|0': 0.875, '((0, 0, 0, 1), (0, 1, 0, 1))|1': 0.8949115044247787}
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

**Observed (real) value:** 0.0025 (var=0.0002)
**Predicted under pi_3:** 0.0013 (var=0.0001)
**Predicted under pi_5:** 0.0016 (var=0.0001)

### Experiment 6
**Design**
  A=[0, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[1, 1, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 0]  B=[1, 0, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 0]  B=[1, 1, 1, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 0, 0, 1]  B=[1, 0, 0, 1]
  A=[0, 1, 1, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
P_REF = {'((1, 0, 0, 0), (1, 1, 1, 0))|0': 0.8360957642725598, '((1, 0, 0, 0), (1, 1, 1, 0))|1': 0.8179271708683473, '((0, 1, 0, 1), (1, 0, 1, 1))|0': 0.6432865731462926, '((0, 1, 0, 1), (1, 0, 1, 1))|1': 0.6717909300538047, '((1, 0, 1, 0), (1, 0, 0, 0))|0': 0.2897727272727273, '((1, 0, 1, 0), (1, 0, 0, 0))|1': 0.23273480662983426, '((0, 0, 1, 1), (1, 0, 1, 1))|0': 0.7685774946921444, '((0, 0, 1, 1), (1, 0, 1, 1))|1': 0.7867132867132867, '((0, 0, 0, 1), (1, 0, 0, 1))|0': 0.7676646706586826, '((0, 0, 0, 1), (1, 0, 0, 1))|1': 0.7927461139896373, '((1, 0, 1, 0), (0, 1, 0, 0))|0': 0.3081232492997199, '((1, 0, 1, 0), (0, 1, 0, 0))|1': 0.3347050754458162, '((0, 1, 0, 0), (1, 0, 0, 0))|0': 0.4606741573033708, '((0, 1, 0, 0), (1, 0, 0, 0))|1': 0.5131690739167375, '((1, 0, 1, 1), (0, 1, 0, 0))|0': 0.22828282828282828, '((1, 0, 1, 1), (0, 1, 0, 0))|1': 0.2074074074074074, '((1, 0, 1, 1), (1, 1, 1, 1))|0': 0.7840565085771948, '((1, 0, 1, 1), (1, 1, 1, 1))|1': 0.7589616810877626, '((0, 0, 1, 1), (0, 1, 0, 0))|0': 0.3566666666666667, '((0, 0, 1, 1), (0, 1, 0, 0))|1': 0.44333333333333336, '((1, 1, 1, 0), (1, 1, 0, 0))|0': 0.23444976076555024, '((1, 1, 1, 0), (1, 1, 0, 0))|1': 0.24175824175824176, '((0, 0, 1, 1), (1, 1, 1, 1))|0': 0.8617131062951496, '((0, 0, 1, 1), (1, 1, 1, 1))|1': 0.8363417569193743, '((1, 0, 1, 1), (0, 1, 0, 1))|0': 0.29088277858176553, '((1, 0, 1, 1), (0, 1, 0, 1))|1': 0.34445446348061315, '((0, 1, 1, 1), (0, 0, 1, 0))|0': 0.16387959866220736, '((0, 1, 1, 1), (0, 0, 1, 0))|1': 0.20364238410596028, '((1, 1, 0, 0), (0, 0, 0, 1))|0': 0.20424107142857142, '((1, 1, 0, 0), (0, 0, 0, 1))|1': 0.23672566371681417, '((1, 1, 0, 0), (1, 0, 1, 1))|0': 0.6392543859649122, '((1, 1, 0, 0), (1, 0, 1, 1))|1': 0.6024774774774775}
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

**Observed (real) value:** 0.0255 (var=0.0004)
**Predicted under pi_3:** 0.0332 (var=0.0004)
**Predicted under pi_5:** 0.0296 (var=0.0002)

### Experiment 7
**Design**
  A=[1, 0, 1, 0]  B=[1, 1, 0, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 0, 1, 0]  B=[1, 1, 0, 1]
  A=[1, 1, 0, 1]  B=[0, 0, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[1, 1, 0, 0]

**Metric**
```python
P_REF = {'((1, 1, 1, 0), (1, 0, 1, 1))|0': 0.13009922822491732, '((1, 1, 1, 0), (1, 0, 1, 1))|1': 0.11758118701007839, '((0, 0, 1, 1), (0, 1, 0, 1))|0': 0.8649253731343284, '((0, 0, 1, 1), (0, 1, 0, 1))|1': 0.8565217391304348, '((0, 0, 1, 1), (1, 0, 0, 0))|0': 0.8809523809523809, '((0, 0, 1, 1), (1, 0, 0, 0))|1': 0.8710045662100456, '((1, 1, 0, 0), (0, 0, 0, 0))|0': 0.11831626848691695, '((1, 1, 0, 0), (0, 0, 0, 0))|1': 0.12052117263843648, '((0, 1, 0, 1), (0, 0, 0, 1))|0': 0.11491712707182321, '((0, 1, 0, 1), (0, 0, 0, 1))|1': 0.13072625698324022, '((1, 1, 1, 1), (0, 0, 0, 0))|0': 0.12354521038495972, '((1, 1, 1, 1), (0, 0, 0, 0))|1': 0.14494875549048317, '((1, 1, 1, 0), (1, 0, 0, 1))|0': 0.12545126353790614, '((1, 1, 1, 0), (1, 0, 0, 1))|1': 0.1329479768786127, '((1, 0, 1, 0), (0, 0, 0, 0))|0': 0.1419642857142857, '((1, 0, 1, 0), (0, 0, 0, 0))|1': 0.13970588235294118, '((0, 0, 1, 1), (0, 0, 0, 0))|0': 0.13085764809902742, '((0, 0, 1, 1), (0, 0, 0, 0))|1': 0.14200298953662183, '((0, 0, 1, 0), (0, 0, 1, 1))|0': 0.8698752228163993, '((0, 0, 1, 0), (0, 0, 1, 1))|1': 0.8775811209439528, '((0, 0, 0, 1), (0, 1, 0, 0))|0': 0.8677130044843049, '((0, 0, 0, 1), (0, 1, 0, 0))|1': 0.8810930576070901, '((1, 1, 0, 1), (0, 0, 1, 1))|0': 0.13148479427549195, '((1, 1, 0, 1), (0, 0, 1, 1))|1': 0.14222873900293256, '((1, 0, 0, 1), (1, 1, 0, 0))|0': 0.857566765578635, '((1, 0, 0, 1), (1, 1, 0, 0))|1': 0.8783303730017762, '((0, 0, 1, 0), (1, 1, 0, 1))|0': 0.8461538461538461, '((0, 0, 1, 0), (1, 1, 0, 1))|1': 0.8674521354933726, '((1, 0, 1, 0), (1, 1, 0, 1))|0': 0.8820798514391829, '((1, 0, 1, 0), (1, 1, 0, 1))|1': 0.8723404255319149, '((1, 0, 0, 1), (0, 0, 1, 1))|0': 0.12456140350877193, '((1, 0, 0, 1), (0, 0, 1, 1))|1': 0.14545454545454545}
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

**Observed (real) value:** 0.0015 (var=0.0001)
**Predicted under pi_3:** 0.0009 (var=0.0001)
**Predicted under pi_5:** 0.0012 (var=0.0001)

### Experiment 8
**Design**
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 1, 0]  B=[1, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 1, 1]
  A=[0, 0, 1, 0]  B=[1, 1, 1, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 0, 0]  B=[1, 0, 1, 0]
  A=[1, 1, 0, 1]  B=[1, 0, 0, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 1]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 1]  B=[1, 0, 1, 0]

**Metric**
```python
P_REF = {'((1, 1, 0, 1), (1, 0, 0, 1))|0': 0.37552155771905427, '((1, 1, 0, 1), (1, 0, 0, 1))|1': 0.303422756706753, '((1, 0, 1, 0), (1, 0, 0, 0))|0': 0.32313829787234044, '((1, 0, 1, 0), (1, 0, 0, 0))|1': 0.31202290076335876, '((1, 1, 1, 0), (1, 0, 0, 1))|0': 0.29945945945945945, '((1, 1, 1, 0), (1, 0, 0, 1))|1': 0.304, '((0, 0, 1, 1), (0, 1, 1, 1))|0': 0.6705744431418523, '((0, 0, 1, 1), (0, 1, 1, 1))|1': 0.6800422386483632, '((1, 1, 1, 1), (0, 0, 1, 0))|0': 0.23143564356435645, '((1, 1, 1, 1), (0, 0, 1, 0))|1': 0.1975806451612903, '((0, 0, 1, 0), (1, 1, 1, 0))|0': 0.7642792384406165, '((0, 0, 1, 0), (1, 1, 1, 0))|1': 0.7173601147776184, '((1, 0, 0, 0), (1, 0, 1, 0))|0': 0.6772009029345373, '((1, 0, 0, 0), (1, 0, 1, 0))|1': 0.6739606126914661, '((1, 0, 1, 1), (1, 0, 1, 0))|0': 0.3538681948424069, '((1, 0, 1, 1), (1, 0, 1, 0))|1': 0.3121597096188748, '((0, 0, 1, 1), (1, 1, 1, 0))|0': 0.7041095890410959, '((0, 0, 1, 1), (1, 1, 1, 0))|1': 0.7021276595744681, '((0, 1, 0, 1), (0, 0, 0, 1))|0': 0.38153846153846155, '((0, 1, 0, 1), (0, 0, 0, 1))|1': 0.3130434782608696, '((0, 1, 1, 0), (1, 0, 0, 0))|0': 0.5597826086956522, '((0, 1, 1, 0), (1, 0, 0, 0))|1': 0.5310344827586206, '((0, 1, 0, 1), (1, 1, 0, 0))|0': 0.6079295154185022, '((0, 1, 0, 1), (1, 1, 0, 0))|1': 0.5896860986547086, '((0, 1, 0, 0), (1, 1, 0, 0))|0': 0.6559766763848397, '((0, 1, 0, 0), (1, 1, 0, 0))|1': 0.6921005385996409, '((0, 0, 1, 1), (1, 0, 1, 1))|0': 0.6754716981132075, '((0, 0, 1, 1), (1, 0, 1, 1))|1': 0.6686567164179105, '((0, 0, 1, 0), (1, 0, 0, 0))|0': 0.6158730158730159, '((0, 0, 1, 0), (1, 0, 0, 0))|1': 0.6035087719298246, '((1, 1, 0, 0), (1, 1, 1, 1))|0': 0.7452135493372607, '((1, 1, 0, 0), (1, 1, 1, 1))|1': 0.7493309545049064}
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

**Observed (real) value:** 0.0167 (var=0.0003)
**Predicted under pi_3:** 0.0277 (var=0.0004)
**Predicted under pi_5:** 0.0240 (var=0.0005)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the eight experiments, neither Take-The-Best (Theory 1) nor Weighted Additive (Theory 2) consistently captures the observed data. Theory 1 (TTB) perfectly predicts the high divergence in Experiment 3 but overestimates in Experiments 4, 6, and 8. Theory 2 (WADD) fits well in Experiments 4, 6, and 8 but completely fails to capture the high divergence observed in Experiment 3. This double dissociation indicates that human subjects are likely using a mixture of strategies or a more flexible evidence accumulation process that can mimic both TTB and WADD depending on the trial structure.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a brand-new 'Strategy Selection Mixture' theory. Instead of strictly applying a single heuristic, decision-makers probabilistically choose between a non-compensatory approach (like Take-The-Best) and a compensatory approach (like Weighted Additive) based on a subject-level or trial-level parameter (e.g., probability of using TTB). This hybrid theory would allow the model to capture experiments where the population leans towards TTB (like Exp 3) as well as those where they integrate all features (like Exp 4 and 8)."
}
```

## Usage

```json
{
  "prompt_token_count": 22313,
  "candidates_token_count": 286,
  "total_token_count": 23554
}
```
