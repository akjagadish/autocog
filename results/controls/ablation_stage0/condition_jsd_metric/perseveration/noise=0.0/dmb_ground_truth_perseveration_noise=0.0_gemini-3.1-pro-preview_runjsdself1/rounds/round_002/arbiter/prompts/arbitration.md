# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_4" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_4" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_4
Population-level Strategy Selection Mixture Model: The population consists of distinct subgroups of decision-makers. Some individuals consistently use a non-compensatory heuristic (Take The Best) while others consistently use a compensatory strategy (Weighted Additive). This discrete between-subject variation in strategy selection accounts for the high individual divergence from the population average, and low lapse rates ensure that the distinct strategy signatures are not washed out by noise.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Expected state to be a (2, n_features) array.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # --- WADD Strategy ---
    score_a_wadd = np.sum(val * a)
    score_b_wadd = np.sum(val * b)
    scores_wadd = np.array([score_a_wadd, score_b_wadd])
    beta_wadd = float(parameters["beta_wadd"])
    z_wadd = beta_wadd * (scores_wadd - np.max(scores_wadd))
    e_wadd = np.exp(z_wadd)
    p_wadd = e_wadd / np.sum(e_wadd)
    
    # --- TTB Strategy ---
    cue_order = np.argsort(-val, kind="stable").tolist()
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        elif b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        p_ttb = np.array([0.5, 0.5])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        beta_ttb = float(parameters["beta_ttb"])
        z_ttb = beta_ttb * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
    # --- Population-level Mixture & Lapse ---
    w_raw = float(parameters["w_wadd"])
    w_wadd = 1.0 if w_raw > 0.5 else 0.0
    p_mix = w_wadd * p_wadd + (1.0 - w_wadd) * p_ttb
    
    epsilon = float(parameters["epsilon"])
    p_final = (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])
    
    return p_final

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

## THEORY 2 — pi_3
People evaluate options using a Weighted Additive (WADD) strategy. Decision-makers compute an overall utility for each option by summing its feature values weighted by their respective cue validities. This compensatory process allows multiple weaker cues to jointly override a single stronger cue if their combined weight is greater. Choice probabilities are then generated via a softmax function over these weighted sums, without an additional lapse rate, allowing for strong deterministic commitments when beta is high.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Weighted additive sums for each option
    score_a = np.sum(val * a)
    score_b = np.sum(val * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    return p_core


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 4: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Rationale:** This design quantitatively dissociates the advocated Strategy Selection model from the pure Weighted Additive (WADD) model. The advocated model can adopt a pure Take The Best (TTB) strategy (when w_wadd < 0.5), whereas the competing model is restricted solely to WADD. By using an environment where the single highest-validity cue is consistently outweighed by the sum of the remaining lower-validity cues, we create trials where TTB and WADD make diametrically opposing predictions. If a substantial portion of the population uses TTB, the advocated model can capture this by switching to the TTB component, while the pure WADD model will fail to fit the choices.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.09031979256698358, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.8833467417538214, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.09040590405904059, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.9240994854202401, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.08519793459552495, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.8990306946688207, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|0': 0.10102739726027397, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 1))|1': 0.9346590909090909, '((0, 1, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.08861301369863013, '((0, 1, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.908685064935065, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.09653994019649723, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.9296461976413176}
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
- Predicted under pi_4 (simulated): 0.0009 (var=0.0007)
- Predicted under pi_3 (simulated): 0.0222 (var=0.0009)
- Observed on real data: 0.0323 (var=0.0000)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=4):** [0.9, 0.8, 0.7, 0.6]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  trial 3: A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  trial 4: A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  trial 5: A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  trial 6: A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  trial 7: A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  trial 8: A=[0, 1, 0, 1]  B=[1, 0, 1, 0]

**Rationale:** To quantitatively dissociate the advocated Weighted Additive (WADD) theory from the competing Strategy Selection Mixture Model, this design maximizes the conflict between compensatory feature-summing (WADD) and non-compensatory one-reason decision making (TTB). We use a 4-feature environment where the most valid cue strongly favors one option, but the sum of the remaining cues outweighs it. By heavily populating the design with trials where TTB and WADD make diametrically opposite predictions, we ensure that the compensatory nature of WADD is rigorously tested.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 0, 1, 1), (1, 1, 0, 0))|0': 0.9261783077796707, '((0, 0, 1, 1), (1, 1, 0, 0))|1': 0.9220272904483431, '((1, 0, 0, 0), (0, 1, 1, 1))|0': 0.9746600741656366, '((1, 0, 0, 0), (0, 1, 1, 1))|1': 0.9757820383451059, '((1, 1, 0, 0), (0, 0, 1, 1))|0': 0.08412887828162291, '((1, 1, 0, 0), (0, 0, 1, 1))|1': 0.07640332640332641, '((1, 0, 0, 1), (0, 1, 1, 0))|0': 0.49951076320939336, '((1, 0, 0, 1), (0, 1, 1, 0))|1': 0.5019280205655527, '((1, 0, 1, 0), (0, 1, 0, 1))|0': 0.16777188328912468, '((1, 0, 1, 0), (0, 1, 0, 1))|1': 0.1534416826003824, '((0, 1, 1, 1), (1, 0, 0, 0))|0': 0.02247191011235955, '((0, 1, 1, 1), (1, 0, 0, 0))|1': 0.02704443013522215, '((0, 1, 0, 1), (1, 0, 1, 0))|0': 0.8273694390715667, '((0, 1, 0, 1), (1, 0, 1, 0))|1': 0.8433420365535248, '((0, 1, 1, 0), (1, 0, 0, 1))|0': 0.5137111517367459, '((0, 1, 1, 0), (1, 0, 0, 1))|1': 0.4834099030117407}
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
- Predicted under pi_4 (simulated): 0.0433 (var=0.0089)
- Predicted under pi_3 (simulated): 0.0007 (var=0.0002)
- Observed on real data: 0.2736 (var=0.0000)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
P_REF = {'((1, 0, 0, 0, 0), (0, 1, 0, 0, 0))|0': 0.15426829268292683, '((1, 0, 0, 0, 0), (0, 1, 0, 0, 0))|1': 0.13289473684210526, '((0, 1, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.13416621401412276, '((0, 1, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.1548311990686845, '((1, 0, 0, 0, 1), (0, 1, 1, 1, 0))|0': 0.1473559120617944, '((1, 0, 0, 0, 1), (0, 1, 1, 1, 0))|1': 0.168141592920354, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|0': 0.8568310781318201, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|1': 0.8190709046454768, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.8608445297504799, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.8051948051948052, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|0': 0.14033898305084747, '((0, 0, 1, 0, 0), (0, 0, 0, 1, 1))|1': 0.14775510204081632, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.1480605487228004, '((1, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.17747440273037543, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.14326923076923076, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.15483870967741936, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.1400214592274678, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.1686602870813397, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 0))|0': 0.14323607427055704, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 0))|1': 0.16319018404907976}
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

**Observed (real) value:** 0.2754 (var=0.0146)
**Predicted under pi_4:** 0.0806 (var=0.0184)
**Predicted under pi_3:** 0.2856 (var=0.0028)

### Experiment 4
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
P_REF = {'((1, 1, 0, 0), (1, 0, 1, 1))|0': 0.8542905692438403, '((1, 1, 0, 0), (1, 0, 1, 1))|1': 0.8503679476696647, '((1, 0, 0, 1), (0, 1, 1, 0))|0': 0.49536850583971004, '((1, 0, 0, 1), (0, 1, 1, 0))|1': 0.4962816063460585, '((1, 0, 0, 0), (0, 1, 1, 1))|0': 0.8673383711167086, '((1, 0, 0, 0), (0, 1, 1, 1))|1': 0.869313482216708, '((0, 1, 1, 1), (1, 0, 0, 0))|0': 0.15443522654754308, '((0, 1, 1, 1), (1, 0, 0, 0))|1': 0.12712650788741106, '((0, 1, 1, 0), (1, 0, 0, 1))|0': 0.49960348929421095, '((0, 1, 1, 0), (1, 0, 0, 1))|1': 0.49209833187006147, '((0, 0, 1, 1), (0, 1, 0, 0))|0': 0.14838930774503084, '((0, 0, 1, 1), (0, 1, 0, 0))|1': 0.15993623804463336}
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

**Observed (real) value:** 0.2502 (var=0.0000)
**Predicted under pi_4:** 0.0437 (var=0.0246)
**Predicted under pi_3:** 0.0111 (var=0.0001)

### Experiment 5
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 0, 1]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 1, 0]

**Metric**
```python
P_REF = {'((0, 1, 0, 1), (0, 0, 1, 1))|0': 0.14573991031390135, '((0, 1, 0, 1), (0, 0, 1, 1))|1': 0.1562043795620438, '((0, 1, 0, 0), (0, 0, 1, 1))|0': 0.14351320321469574, '((0, 1, 0, 0), (0, 0, 1, 1))|1': 0.1691995947315096, '((1, 0, 0, 1), (0, 1, 1, 0))|0': 0.14623069936421434, '((1, 0, 0, 1), (0, 1, 1, 0))|1': 0.1680972818311874, '((1, 0, 0, 0), (0, 1, 1, 1))|0': 0.15313582146979607, '((1, 0, 0, 0), (0, 1, 1, 1))|1': 0.1798201798201798, '((0, 1, 1, 0), (1, 0, 0, 0))|0': 0.8592085235920852, '((0, 1, 1, 0), (1, 0, 0, 0))|1': 0.8292181069958847, '((0, 1, 1, 1), (1, 0, 1, 0))|0': 0.85413808870599, '((0, 1, 1, 1), (1, 0, 1, 0))|1': 0.825696316262354, '((1, 0, 0, 0), (0, 1, 0, 1))|0': 0.15325842696629213, '((1, 0, 0, 0), (0, 1, 0, 1))|1': 0.16290909090909092, '((1, 0, 0, 0), (0, 0, 1, 1))|0': 0.15387805889672335, '((1, 0, 0, 0), (0, 0, 1, 1))|1': 0.16568544995794784}
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

**Observed (real) value:** 0.2622 (var=0.0102)
**Predicted under pi_4:** 0.0794 (var=0.0173)
**Predicted under pi_3:** 0.2525 (var=0.0040)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
P_REF = {'((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|0': 0.056291390728476824, '((0, 1, 1, 0, 0), (1, 0, 0, 0, 0))|1': 0.05550239234449761, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|0': 0.9157043879907621, '((1, 0, 1, 0, 0), (0, 1, 0, 1, 1))|1': 0.8852295409181636, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|0': 0.9618218352310783, '((1, 1, 0, 0, 0), (1, 0, 1, 1, 1))|1': 0.9663028001898434, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|0': 0.02889324191968658, '((1, 0, 1, 1, 1), (1, 1, 0, 0, 0))|1': 0.029525032092426188, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|0': 0.963302752293578, '((0, 1, 0, 0, 0), (0, 0, 1, 1, 1))|1': 0.961412688031393, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|0': 0.9685452162516383, '((1, 0, 0, 0, 0), (0, 1, 1, 1, 0))|1': 0.9802314368370298, '((0, 0, 1, 1, 1), (0, 1, 0, 0, 0))|0': 0.04818325434439179, '((0, 0, 1, 1, 1), (0, 1, 0, 0, 0))|1': 0.029006882989183875, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|0': 0.09690177982860909, '((0, 1, 0, 1, 1), (1, 0, 1, 0, 0))|1': 0.09649543927028324}
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

**Observed (real) value:** 0.3086 (var=0.0000)
**Predicted under pi_4:** 0.1631 (var=0.0677)
**Predicted under pi_3:** 0.0006 (var=0.0005)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, we can determine the true fit by looking at the JSD-to-self metrics. Experiments 2, 4, and 6 were proposed by Theory 2 (pi_3), meaning the metric calculates the divergence from Theory 2's predictions. In these experiments, Theory 2 naturally predicts a JSD near 0, but the observed data consistently shows a high divergence (0.25 to 0.30). This implies the real data strongly deviates from the pure Weighted Additive (WADD) strategy. Conversely, Experiments 3 and 5 were likely proposed by Theory 1 (pi_4), where Theory 1 predicted JSDs near 0, but the observed data again showed high divergence (~0.26 to 0.27). Theory 1's mixture of WADD and TTB also fails to capture the true human behavior. Neither theory accurately predicts the choices, suggesting that participants are likely using a different strategy entirely, such as Tallying (simply counting the number of positive features for each option regardless of validity weights) or applying a non-linear transformation to the given validities.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a completely new theory based on the 'Tallying' (Equal Weight) heuristic. Instead of computing a weighted sum using the exact expert validities (as in WADD) or strictly following the single best cue (as in TTB), decision-makers simply count the total number of positive features for each option. The option with the higher count is chosen, and choices are generated via a softmax function over these unweighted counts. This represents a boundedly rational approach that ignores complex validity weights to reduce cognitive load."
}
```

## Usage

```json
{
  "prompt_token_count": 11822,
  "candidates_token_count": 383,
  "total_token_count": 13717
}
```
