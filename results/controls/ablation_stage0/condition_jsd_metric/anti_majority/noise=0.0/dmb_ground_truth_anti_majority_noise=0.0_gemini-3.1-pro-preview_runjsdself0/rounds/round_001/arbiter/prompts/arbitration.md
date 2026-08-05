# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
People compare two options by consulting cues one at a time in order of validity, stopping at the first cue that discriminates between the two options. That cue alone determines the choice: the option with the higher value on the discriminating cue wins, and no other cue is consulted. Cues with lower validity are never reached when a higher-validity cue already discriminates, so Take The Best is a "one-reason" decision rule — only a single feature is ever used on any given choice. Because only the sign of the comparison on the top discriminating cue matters, TTB ignores both the magnitude of that difference and all information on lower-validity cues, making it maximally frugal in the use of evidence. Cue validities are subjective and can be learned, inferred from instructions, or fixed by task structure. When no cue discriminates (all feature-wise comparisons tie) the learner has no basis for preference and must guess. Response noise enters through a softmax over the binary TTB score (winner = 1, loser = 0) with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Take The Best (Gigerenzer & Goldstein 1996).
    # Stimulus is the pair of option feature vectors for the current
    # trial: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B. Cue cascade: features are consulted in order
    # of descending validity; the first discriminating cue (strict
    # inequality) determines the winner; if no cue discriminates,
    # the model guesses uniformly. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )
    # Descending validity; argsort is stable so validity ties break
    # toward the earlier feature index.
    cue_order = np.argsort(-val, kind="stable").tolist()

    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        if b[j] > a[j]:
            winner = 1
            break

    if winner is None:
        # No discriminating cue — pure guess.
        return np.ones(2) / 2.0

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the
    # binary TTB score this collapses to sigmoid(beta) for the winner,
    # giving a direct mapping from beta onto the paper's flip-noise
    # levels (beta=0 ↔ 50/50; beta ≫ 1 ↔ deterministic).
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_3
People integrate all available evidence by weighting each feature according to its validity. Specifically, they compute a weighted sum of the features for each option, where the weights are the log-odds of the cue validities. This allows for compensatory decision making, where multiple weaker cues can jointly override a single stronger cue. Choice probabilities are generated via a softmax function over these weighted sums, accommodating response noise, along with an independent lapse rate for random guessing.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
    
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Monotonic transformation of validities to log-odds
    # Clip to avoid division by zero or infinite weights
    val_clipped = np.clip(val, 0.5001, 0.9999)
    weights = np.log(val_clipped / (1.0 - val_clipped))
    
    # Calculate weighted additive score for each option
    scores = np.dot(stim, weights)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(scores)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=5):** [0.8, 0.75, 0.7, 0.65, 0.6]

**Trial pairs (n=5):**
  trial 1: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 2: A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 5: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Rationale:** To quantitatively dissociate Take The Best (TTB) from the Weighted Additive (WADD) model, we use 5 features with validities chosen such that the log-odds weight of any single feature is smaller than the combined log-odds weights of the features ranked below it. In the critical trials, the option favored by the highest-validity discriminating cue (the TTB choice) is opposed by an option that has a greater number of lower-validity cues in its favor. Because WADD integrates all evidence via a weighted sum (compensatory), it predicts that the accumulation of weaker cues will override the single best cue. TTB, being non-compensatory, strictly follows the single highest-validity discriminating cue. We also include agreement trials where the two models make the same choice but with different confidence margins.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|0': 0.8371659415786202, '((0, 1, 1, 1, 1), (1, 0, 0, 0, 0))|1': 0.859447567831826, '((1, 1, 0, 1, 1), (1, 1, 1, 0, 0))|0': 0.8092909535452323, '((1, 1, 0, 1, 1), (1, 1, 1, 0, 0))|1': 0.855739276300024, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|0': 0.1607806691449814, '((1, 0, 0, 1, 1), (0, 1, 1, 0, 0))|1': 0.14261555806087936, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.8188010899182562, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.8620037807183365, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.8426698450536353, '((0, 1, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.8707110890104426}
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
- Predicted under pi_1 (simulated): 0.0002 (var=0.0002)
- Predicted under pi_3 (simulated): 0.1371 (var=0.0024)
- Observed on real data: 0.1151 (var=0.0017)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.88, 0.82, 0.78, 0.74, 0.68]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 5: A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 6: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]

**Rationale:** To quantitatively dissociate the Weighted Additive (WADD) model from Take The Best (TTB), we configure 5 features with validities such that the log-odds weight of the most valid cue is smaller than the combined log-odds weights of multiple lower-validity cues. In our critical trials, the option favored by the single highest-validity discriminating cue (the TTB choice) is opposed by the option that possesses a greater number of lower-validity cues. Because WADD integrates all evidence via a compensatory weighted sum, it predicts that the accumulation of weaker cues will override the single best cue. TTB, being strictly non-compensatory, will always choose the option favored by the first discriminating cue regardless of the lower-validity cues.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|0': 0.16258919469928645, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|1': 0.15760441292356187, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.8594682582745523, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.8654041258031789, '((1, 0, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.8035264483627204, '((1, 0, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.8275217932752179, '((1, 0, 0, 0, 1), (0, 1, 1, 0, 0))|0': 0.5700483091787439, '((1, 0, 0, 0, 1), (0, 1, 1, 0, 0))|1': 0.5649402390438247, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.8424556213017751, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.8700696055684455, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.8271474019088016, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.8685506870624838}
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
- Predicted under pi_1 (simulated): 0.2258 (var=0.0061)
- Predicted under pi_3 (simulated): 0.0006 (var=0.0001)
- Observed on real data: 0.2052 (var=0.0083)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
P_REF = {'((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.1458546571136131, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.1589895988112927, '((1, 0, 0, 1, 1), (1, 1, 1, 0, 0))|0': 0.8495702005730659, '((1, 0, 0, 1, 1), (1, 1, 1, 0, 0))|1': 0.8625226860254084, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.16703296703296702, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.14675615212527965, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|0': 0.8453101361573374, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|1': 0.8483263598326359, '((0, 0, 1, 1, 1), (0, 1, 0, 0, 0))|0': 0.8259762308998302, '((0, 0, 1, 1, 1), (0, 1, 0, 0, 0))|1': 0.8323699421965318, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 0))|0': 0.8504672897196262, '((0, 1, 1, 1, 0), (1, 0, 0, 0, 0))|1': 0.8556990454800674, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.1448481831757093, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.1583909490886235, '((1, 1, 1, 0, 0), (1, 0, 0, 1, 1))|0': 0.16117764471057885, '((1, 1, 1, 0, 0), (1, 0, 0, 1, 1))|1': 0.13972431077694236}
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

**Observed (real) value:** 0.0720 (var=0.0033)
**Predicted under pi_1:** 0.0009 (var=0.0001)
**Predicted under pi_3:** 0.1052 (var=0.0021)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]

**Metric**
```python
P_REF = {'((0, 1, 1, 1), (1, 0, 0, 0))|0': 0.13289658399625642, '((0, 1, 1, 1), (1, 0, 0, 0))|1': 0.1367053998632946, '((1, 0, 1, 0), (0, 1, 0, 1))|0': 0.482837528604119, '((1, 0, 1, 0), (0, 1, 0, 1))|1': 0.49584971603320227, '((0, 1, 1, 0), (1, 0, 0, 1))|0': 0.5096097845078625, '((0, 1, 1, 0), (1, 0, 0, 1))|1': 0.49814126394052044, '((1, 1, 0, 0), (1, 0, 1, 1))|0': 0.8581730769230769, '((1, 1, 0, 0), (1, 0, 1, 1))|1': 0.8388429752066116, '((1, 0, 0, 0), (0, 1, 1, 0))|0': 0.8467995802728226, '((1, 0, 0, 0), (0, 1, 1, 0))|1': 0.8524203069657615, '((1, 0, 1, 1), (1, 1, 0, 0))|0': 0.15416451112260735, '((1, 0, 1, 1), (1, 1, 0, 0))|1': 0.14697060587882424, '((0, 1, 0, 0), (0, 0, 1, 1))|0': 0.8478802992518704, '((0, 1, 0, 0), (0, 0, 1, 1))|1': 0.8612224448897795, '((0, 0, 1, 1), (1, 0, 0, 0))|0': 0.144905273937532, '((0, 0, 1, 1), (1, 0, 0, 0))|1': 0.14179658500371195}
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

**Observed (real) value:** 0.1803 (var=0.0062)
**Predicted under pi_1:** 0.2218 (var=0.0077)
**Predicted under pi_3:** 0.0978 (var=0.0010)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the four experiments, neither pure Take The Best (THEORY 1) nor pure Weighted Additive (THEORY 2) consistently captures the observed data. In Experiment 1, the observed JSD (0.1151) is much closer to the WADD prediction (0.1371) than the TTB prediction (0.0002). However, in Experiment 2, the observed JSD (0.2052) is closer to the TTB prediction (0.2258) than the WADD prediction (0.0006). In Experiments 3 and 4, the observed data falls between the predictions of the two extremes. This suggests that human decision-making in this domain is not exclusively non-compensatory or compensatory, but rather exhibits properties of both, either through individual differences (a mixture of strategies) or a unified mechanism that spans both extremes.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a unified sequential evidence accumulation theory (e.g., a threshold model). In this theory, subjects consult cues in order of validity and accumulate evidence (e.g., the log-odds weights of the discriminating cues). After each cue, if the accumulated evidence difference between the two options exceeds a certain internal threshold, the subject stops and makes a choice. If the threshold is low, this model perfectly mimics Take The Best (stopping at the first discriminating cue). If the threshold is high, it mimics the Weighted Additive model (integrating all available cues). This single mechanism can naturally capture the intermediate and context-dependent behavior observed across all experiments."
}
```

## Usage

```json
{
  "prompt_token_count": 8633,
  "candidates_token_count": 363,
  "total_token_count": 9908
}
```
