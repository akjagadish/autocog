# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_6" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_6" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_6
Final result: Validity-Gated Tallying implemented with a differentiable sigmoid threshold approximation.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    threshold = float(parameters["threshold"])
    epsilon = float(parameters["epsilon"])
    
    trusted_weights = 1.0 / (1.0 + np.exp(-100.0 * (validities - threshold)))
    
    tally_a = np.sum(a * trusted_weights)
    tally_b = np.sum(b * trusted_weights)
    
    if tally_a > tally_b:
        p_core = np.array([1.0, 0.0])
    elif tally_b > tally_a:
        p_core = np.array([0.0, 1.0])
    else:
        p_core = np.array([0.5, 0.5])
        
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))

## THEORY 2 — pi_4
Two-Stage Heuristic (Hybrid TTB-Tallying over Remaining Cues): Decision makers use a bounded sequential search, initially relying on the most valid cues to discriminate between options (Take-The-Best). If the top 'k' cues fail to discriminate (i.e., they are tied), the decision maker falls back to a computationally simpler 'Tallying' strategy. However, instead of tallying all cues, they only tally the remaining unexamined cues, avoiding double-counting the cues that already tied. This provides a psychologically plausible sequential search process that blends lexicographic and tallying strategies.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Rank features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    k = int(parameters["max_cues"])
    
    decided = False
    p_core = np.array([0.5, 0.5])
    
    # Stage 1: Take-The-Best on the top k cues
    for idx in order[:k]:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            decided = True
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            decided = True
            break
            
    # Stage 2: Fallback to Tallying on remaining unexamined cues if top cues tie
    if not decided:
        remaining_order = order[k:]
        if len(remaining_order) > 0:
            a_rem = a[remaining_order]
            b_rem = b[remaining_order]
            a_wins = float(np.sum(a_rem > b_rem))
            b_wins = float(np.sum(b_rem > a_rem))
            if a_wins > b_wins:
                p_core = np.array([1.0, 0.0])
            elif b_wins > a_wins:
                p_core = np.array([0.0, 1.0])
            else:
                p_core = np.array([0.5, 0.5])
        else:
            p_core = np.array([0.5, 0.5])
            
    epsilon = float(parameters["epsilon"])
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_6)

### DESIGN
**Validities (n_features=4):** [0.95, 0.81, 0.81, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  trial 2: A=[0, 0, 1, 0]  B=[1, 0, 0, 1]
  trial 3: A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  trial 4: A=[0, 1, 0, 1]  B=[1, 0, 1, 1]
  trial 5: A=[1, 0, 0, 1]  B=[1, 0, 1, 1]
  trial 6: A=[0, 0, 0, 1]  B=[0, 0, 1, 0]
  trial 7: A=[1, 1, 1, 1]  B=[0, 1, 0, 1]
  trial 8: A=[1, 0, 1, 1]  B=[0, 1, 0, 1]
  trial 9: A=[1, 0, 1, 0]  B=[1, 1, 1, 0]
  trial 10: A=[1, 0, 1, 1]  B=[1, 0, 0, 1]
  trial 11: A=[1, 1, 0, 1]  B=[1, 1, 1, 0]
  trial 12: A=[0, 1, 0, 0]  B=[1, 1, 1, 1]
  trial 13: A=[0, 1, 1, 1]  B=[1, 0, 1, 0]
  trial 14: A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  trial 15: A=[0, 1, 1, 1]  B=[1, 1, 0, 1]
  trial 16: A=[0, 0, 0, 0]  B=[1, 0, 1, 0]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 0, 0, 1), (0, 0, 1, 0))|0': 0.7921348314606742, '((0, 0, 0, 1), (0, 0, 1, 0))|1': 0.8216911764705882, '((1, 0, 1, 1), (1, 0, 0, 1))|0': 0.12317327766179541, '((1, 0, 1, 1), (1, 0, 0, 1))|1': 0.10186092066601371, '((1, 0, 0, 1), (1, 0, 1, 1))|0': 0.8571428571428571, '((1, 0, 0, 1), (1, 0, 1, 1))|1': 0.8814070351758794, '((0, 1, 0, 1), (1, 1, 0, 0))|0': 0.8228004956629492, '((0, 1, 0, 1), (1, 1, 0, 0))|1': 0.8116817724068479, '((0, 1, 0, 0), (1, 1, 1, 1))|0': 0.8561643835616438, '((0, 1, 0, 0), (1, 1, 1, 1))|1': 0.886604774535809, '((1, 1, 1, 1), (0, 1, 0, 1))|0': 0.1357142857142857, '((1, 1, 1, 1), (0, 1, 0, 1))|1': 0.11097560975609756, '((1, 0, 1, 1), (0, 1, 0, 1))|0': 0.13636363636363635, '((1, 0, 1, 1), (0, 1, 0, 1))|1': 0.1104014598540146, '((1, 0, 1, 0), (1, 1, 1, 0))|0': 0.8716981132075472, '((1, 0, 1, 0), (1, 1, 1, 0))|1': 0.8729729729729729, '((0, 1, 0, 1), (1, 0, 1, 1))|0': 0.8808373590982287, '((0, 1, 0, 1), (1, 0, 1, 1))|1': 0.9007633587786259, '((0, 0, 0, 0), (1, 0, 1, 0))|0': 0.8223234624145785, '((0, 0, 0, 0), (1, 0, 1, 0))|1': 0.8897869213813373, '((0, 1, 1, 1), (1, 1, 0, 1))|0': 0.6948775055679287, '((0, 1, 1, 1), (1, 1, 0, 1))|1': 0.7142857142857143, '((0, 0, 1, 0), (1, 0, 0, 1))|0': 0.8745387453874539, '((0, 0, 1, 0), (1, 0, 0, 1))|1': 0.8712241653418124, '((1, 1, 0, 1), (1, 1, 1, 0))|0': 0.8233502538071066, '((1, 1, 0, 1), (1, 1, 1, 0))|1': 0.8208588957055215, '((1, 1, 0, 0), (1, 0, 1, 1))|0': 0.8550512445095169, '((1, 1, 0, 0), (1, 0, 1, 1))|1': 0.8343777976723367, '((0, 1, 1, 1), (1, 0, 1, 0))|0': 0.29411764705882354, '((0, 1, 1, 1), (1, 0, 1, 0))|1': 0.3739245532759762, '((1, 0, 0, 1), (1, 0, 0, 0))|0': 0.15138282387190685, '((1, 0, 0, 1), (1, 0, 0, 0))|1': 0.14106019766397124}
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
- Predicted under pi_6 (simulated): 0.0010 (var=0.0001)
- Predicted under pi_4 (simulated): 0.0121 (var=0.0001)
- Observed on real data: 0.0293 (var=0.0001)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=4):** [0.95, 0.6, 0.76, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[0, 0, 1, 1]  B=[1, 1, 1, 0]
  trial 2: A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  trial 3: A=[1, 1, 1, 0]  B=[1, 1, 0, 0]
  trial 4: A=[0, 0, 1, 1]  B=[1, 1, 1, 0]
  trial 5: A=[1, 0, 1, 1]  B=[1, 1, 0, 1]
  trial 6: A=[0, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 7: A=[0, 1, 0, 1]  B=[1, 0, 0, 0]
  trial 8: A=[1, 0, 1, 0]  B=[1, 0, 0, 0]
  trial 9: A=[1, 1, 1, 1]  B=[0, 1, 1, 1]
  trial 10: A=[0, 1, 1, 1]  B=[0, 1, 0, 1]
  trial 11: A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 12: A=[0, 1, 1, 1]  B=[1, 0, 1, 0]
  trial 13: A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 14: A=[0, 1, 1, 0]  B=[0, 0, 0, 0]
  trial 15: A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  trial 16: A=[0, 0, 1, 1]  B=[0, 0, 0, 0]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 0, 0, 0), (0, 1, 1, 0))|0': 0.13099041533546327, '((1, 0, 0, 0), (0, 1, 1, 0))|1': 0.17446808510638298, '((0, 1, 1, 1), (0, 0, 0, 0))|0': 0.11888638073739653, '((0, 1, 1, 1), (0, 0, 0, 0))|1': 0.14861995753715498, '((1, 1, 1, 1), (0, 1, 1, 1))|0': 0.11997019374068554, '((1, 1, 1, 1), (0, 1, 1, 1))|1': 0.1462882096069869, '((1, 0, 0, 0), (0, 1, 1, 1))|0': 0.1408987052551409, '((1, 0, 0, 0), (0, 1, 1, 1))|1': 0.10677618069815195, '((1, 0, 1, 0), (1, 0, 0, 0))|0': 0.12692656391659113, '((1, 0, 1, 0), (1, 0, 0, 0))|1': 0.1406025824964132, '((1, 0, 1, 1), (1, 1, 0, 1))|0': 0.2112676056338028, '((1, 0, 1, 1), (1, 1, 0, 1))|1': 0.2616407982261641, '((0, 1, 0, 1), (1, 0, 0, 0))|0': 0.8734402852049911, '((0, 1, 0, 1), (1, 0, 0, 0))|1': 0.859882005899705, '((0, 0, 1, 1), (1, 1, 1, 0))|0': 0.868018018018018, '((0, 0, 1, 1), (1, 1, 1, 0))|1': 0.8615942028985507, '((0, 1, 1, 1), (1, 0, 1, 0))|0': 0.8794642857142857, '((0, 1, 1, 1), (1, 0, 1, 0))|1': 0.8808823529411764, '((1, 1, 1, 0), (1, 1, 0, 0))|0': 0.12733260153677278, '((1, 1, 1, 0), (1, 1, 0, 0))|1': 0.12260967379077616, '((1, 1, 1, 1), (0, 0, 0, 0))|0': 0.12469635627530365, '((1, 1, 1, 1), (0, 0, 0, 0))|1': 0.12477876106194691, '((0, 1, 1, 1), (0, 1, 0, 1))|0': 0.1360544217687075, '((0, 1, 1, 1), (0, 1, 0, 1))|1': 0.129979035639413, '((0, 0, 1, 1), (0, 0, 0, 0))|0': 0.13088512241054615, '((0, 0, 1, 1), (0, 0, 0, 0))|1': 0.1552511415525114, '((0, 1, 1, 0), (0, 0, 0, 0))|0': 0.1266294227188082, '((0, 1, 1, 0), (0, 0, 0, 0))|1': 0.12396694214876033}
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
- Predicted under pi_6 (simulated): 0.0376 (var=0.0015)
- Predicted under pi_4 (simulated): 0.0016 (var=0.0001)
- Observed on real data: 0.0017 (var=0.0001)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 1, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 1]  B=[0, 1, 1, 0]

**Metric**
```python
P_REF = {'((0, 1, 0, 0), (0, 1, 1, 0))|0': 0.8471337579617835, '((0, 1, 0, 0), (0, 1, 1, 0))|1': 0.8368298368298368, '((1, 1, 0, 1), (0, 1, 1, 0))|0': 0.17772215269086358, '((1, 1, 0, 1), (0, 1, 1, 0))|1': 0.16583416583416583, '((1, 0, 0, 1), (0, 0, 1, 0))|0': 0.15309734513274337, '((1, 0, 0, 1), (0, 0, 1, 0))|1': 0.1537313432835821, '((0, 0, 0, 1), (1, 1, 0, 0))|0': 0.8552522746071133, '((0, 0, 0, 1), (1, 1, 0, 0))|1': 0.8324873096446701, '((1, 0, 1, 0), (0, 0, 0, 0))|0': 0.16329479768786126, '((1, 0, 1, 0), (0, 0, 0, 0))|1': 0.1299638989169675, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8578052550231839, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8640093786635404, '((0, 0, 0, 0), (1, 1, 0, 0))|0': 0.8636779505946935, '((0, 0, 0, 0), (1, 1, 0, 0))|1': 0.8458274398868458, '((1, 1, 1, 1), (0, 0, 1, 0))|0': 0.11648568608094768, '((1, 1, 1, 1), (0, 0, 1, 0))|1': 0.16010165184243966, '((1, 1, 0, 1), (1, 1, 1, 0))|0': 0.49140271493212667, '((1, 1, 0, 1), (1, 1, 1, 0))|1': 0.5179856115107914, '((1, 1, 1, 0), (0, 1, 1, 1))|0': 0.5100502512562815, '((1, 1, 1, 0), (0, 1, 1, 1))|1': 0.49302788844621515, '((1, 1, 1, 1), (0, 0, 0, 1))|0': 0.10619469026548672, '((1, 1, 1, 1), (0, 0, 0, 1))|1': 0.11892963330029732, '((0, 1, 0, 1), (1, 1, 0, 0))|0': 0.512781954887218, '((0, 1, 0, 1), (1, 1, 0, 0))|1': 0.474468085106383, '((1, 1, 1, 1), (0, 0, 0, 0))|0': 0.12003311258278146, '((1, 1, 1, 1), (0, 0, 0, 0))|1': 0.13175675675675674, '((1, 0, 0, 1), (1, 0, 0, 0))|0': 0.14905814905814907, '((1, 0, 0, 1), (1, 0, 0, 0))|1': 0.15889464594127806, '((1, 0, 1, 1), (1, 1, 1, 0))|0': 0.508296943231441, '((1, 0, 1, 1), (1, 1, 1, 0))|1': 0.4900763358778626, '((0, 0, 1, 1), (1, 0, 1, 1))|0': 0.8048780487804879, '((0, 0, 1, 1), (1, 0, 1, 1))|1': 0.8489451476793249}
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

**Observed (real) value:** 0.0205 (var=0.0002)
**Predicted under pi_6:** 0.0161 (var=0.0003)
**Predicted under pi_4:** 0.0158 (var=0.0002)

### Experiment 4
**Design**
  A=[1, 1, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 0, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[0, 0, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[0, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 1, 1, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 1, 0]

**Metric**
```python
P_REF = {'((0, 0, 0, 1), (0, 0, 1, 1))|0': 0.7913950456323338, '((0, 0, 0, 1), (0, 0, 1, 1))|1': 0.7831558567279767, '((1, 0, 1, 1), (1, 0, 0, 0))|0': 0.2125, '((1, 0, 1, 1), (1, 0, 0, 0))|1': 0.17314814814814813, '((0, 1, 0, 1), (0, 0, 1, 0))|0': 0.3384201077199282, '((0, 1, 0, 1), (0, 0, 1, 0))|1': 0.35276967930029157, '((0, 0, 0, 0), (0, 1, 1, 0))|0': 0.8560700876095119, '((0, 0, 0, 0), (0, 1, 1, 0))|1': 0.8271728271728271, '((1, 1, 1, 0), (1, 0, 1, 0))|0': 0.22364217252396165, '((1, 1, 1, 0), (1, 0, 1, 0))|1': 0.206984667802385, '((0, 1, 0, 1), (0, 0, 0, 1))|0': 0.2425249169435216, '((0, 1, 0, 1), (0, 0, 0, 1))|1': 0.21962095875139354, '((0, 0, 1, 1), (1, 1, 0, 1))|0': 0.7389858686616791, '((0, 0, 1, 1), (1, 1, 0, 1))|1': 0.6549413735343383, '((1, 0, 0, 1), (0, 1, 0, 0))|0': 0.2998805256869773, '((1, 0, 0, 1), (0, 1, 0, 0))|1': 0.3052959501557632, '((1, 1, 0, 1), (0, 1, 1, 1))|0': 0.45555555555555555, '((1, 1, 0, 1), (0, 1, 1, 1))|1': 0.45308641975308644, '((0, 0, 0, 0), (1, 0, 1, 1))|0': 0.8474387527839644, '((0, 0, 0, 0), (1, 0, 1, 1))|1': 0.835920177383592, '((0, 1, 0, 1), (1, 1, 1, 1))|0': 0.8377125193199382, '((0, 1, 0, 1), (1, 1, 1, 1))|1': 0.8475967174677609, '((0, 1, 1, 0), (0, 0, 0, 0))|0': 0.16120906801007556, '((0, 1, 1, 0), (0, 0, 0, 0))|1': 0.17693836978131214, '((0, 1, 0, 0), (0, 1, 1, 0))|0': 0.7583444592790387, '((0, 1, 0, 0), (0, 1, 1, 0))|1': 0.7916270218839201, '((0, 0, 0, 1), (0, 1, 1, 1))|0': 0.8501026694045175, '((0, 0, 0, 1), (0, 1, 1, 1))|1': 0.8317191283292978, '((1, 0, 1, 1), (0, 1, 0, 1))|0': 0.2862669245647969, '((1, 0, 1, 1), (0, 1, 0, 1))|1': 0.24551831644583008, '((0, 1, 1, 0), (1, 0, 1, 0))|0': 0.4927675988428158, '((0, 1, 1, 0), (1, 0, 1, 0))|1': 0.583224115334207}
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

**Observed (real) value:** 0.0172 (var=0.0002)
**Predicted under pi_6:** 0.0090 (var=0.0002)
**Predicted under pi_4:** 0.0175 (var=0.0002)

### Experiment 5
**Design**
  A=[1, 1, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 1, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 0, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]

**Metric**
```python
P_REF = {'((1, 0, 0, 0), (1, 1, 0, 0))|0': 0.8840579710144928, '((1, 0, 0, 0), (1, 1, 0, 0))|1': 0.8748615725359912, '((1, 0, 1, 1), (1, 0, 0, 1))|0': 0.11559139784946236, '((1, 0, 1, 1), (1, 0, 0, 1))|1': 0.12134502923976608, '((1, 0, 1, 0), (1, 1, 0, 0))|0': 0.1378692927484333, '((1, 0, 1, 0), (1, 1, 0, 0))|1': 0.14641288433382138, '((1, 0, 1, 0), (1, 0, 0, 0))|0': 0.10933333333333334, '((1, 0, 1, 0), (1, 0, 0, 0))|1': 0.1362962962962963, '((0, 1, 1, 0), (1, 1, 0, 0))|0': 0.8860648553900088, '((0, 1, 1, 0), (1, 1, 0, 0))|1': 0.874051593323217, '((1, 0, 1, 1), (1, 0, 1, 0))|0': 0.11531531531531532, '((1, 0, 1, 1), (1, 0, 1, 0))|1': 0.14202898550724638, '((1, 1, 1, 1), (1, 1, 0, 1))|0': 0.1309823677581864, '((1, 1, 1, 1), (1, 1, 0, 1))|1': 0.1650943396226415, '((1, 1, 1, 0), (0, 0, 0, 1))|0': 0.1084070796460177, '((1, 1, 1, 0), (0, 0, 0, 1))|1': 0.11160714285714286, '((1, 1, 1, 1), (1, 0, 1, 0))|0': 0.10942441492726122, '((1, 1, 1, 1), (1, 0, 1, 0))|1': 0.2146118721461187, '((0, 1, 0, 0), (1, 1, 1, 1))|0': 0.860832137733142, '((0, 1, 0, 0), (1, 1, 1, 1))|1': 0.8712601994560291, '((1, 0, 0, 0), (0, 1, 0, 0))|0': 0.11829134720700986, '((1, 0, 0, 0), (0, 1, 0, 0))|1': 0.11161217587373168, '((1, 1, 0, 0), (0, 0, 0, 1))|0': 0.14411764705882352, '((1, 1, 0, 0), (0, 0, 0, 1))|1': 0.12142857142857143, '((1, 0, 0, 0), (1, 0, 0, 1))|0': 0.8772378516624041, '((1, 0, 0, 0), (1, 0, 0, 1))|1': 0.8177966101694916, '((1, 0, 0, 1), (0, 0, 1, 0))|0': 0.10836501901140684, '((1, 0, 0, 1), (0, 0, 1, 0))|1': 0.1891891891891892, '((1, 0, 1, 0), (0, 1, 0, 1))|0': 0.11185682326621924, '((1, 0, 1, 0), (0, 1, 0, 1))|1': 0.16993464052287582, '((0, 1, 0, 0), (0, 0, 1, 1))|0': 0.8882733148661126, '((0, 1, 0, 0), (0, 0, 1, 1))|1': 0.8729016786570744}
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

**Observed (real) value:** 0.0038 (var=0.0001)
**Predicted under pi_6:** 0.0048 (var=0.0003)
**Predicted under pi_4:** 0.0020 (var=0.0001)

### Experiment 6
**Design**
  A=[0, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 0]
  A=[0, 0, 1, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[0, 1, 1, 1]

**Metric**
```python
P_REF = {'((0, 1, 0, 1), (1, 1, 1, 0))|0': 0.6834677419354839, '((0, 1, 0, 1), (1, 1, 1, 0))|1': 0.75, '((1, 1, 1, 0), (1, 0, 0, 1))|0': 0.2972972972972973, '((1, 1, 1, 0), (1, 0, 0, 1))|1': 0.3210930828351836, '((1, 1, 0, 0), (0, 1, 1, 1))|0': 0.5884861407249466, '((1, 1, 0, 0), (0, 1, 1, 1))|1': 0.525522041763341, '((0, 0, 1, 0), (1, 1, 1, 1))|0': 0.8384074941451991, '((0, 0, 1, 0), (1, 1, 1, 1))|1': 0.8456659619450317, '((1, 1, 0, 0), (0, 0, 1, 0))|0': 0.23440453686200377, '((1, 1, 0, 0), (0, 0, 1, 0))|1': 0.2749326145552561, '((1, 1, 1, 1), (0, 0, 0, 0))|0': 0.15806451612903225, '((1, 1, 1, 1), (0, 0, 0, 0))|1': 0.1875, '((0, 1, 1, 0), (0, 0, 1, 1))|0': 0.4133489461358314, '((0, 1, 1, 0), (0, 0, 1, 1))|1': 0.5232558139534884, '((1, 1, 0, 0), (1, 0, 1, 1))|0': 0.6568627450980392, '((1, 1, 0, 0), (1, 0, 1, 1))|1': 0.7034990791896869, '((1, 0, 0, 1), (1, 1, 0, 0))|0': 0.48372781065088755, '((1, 0, 0, 1), (1, 1, 0, 0))|1': 0.5204626334519573, '((0, 1, 1, 0), (0, 0, 0, 1))|0': 0.3069544364508393, '((0, 1, 1, 0), (0, 0, 0, 1))|1': 0.3115942028985507, '((0, 0, 0, 0), (0, 0, 1, 1))|0': 0.8237082066869301, '((0, 0, 0, 0), (0, 0, 1, 1))|1': 0.8081180811808119, '((0, 0, 1, 1), (1, 1, 1, 1))|0': 0.823943661971831, '((0, 0, 1, 1), (1, 1, 1, 1))|1': 0.8312236286919831, '((1, 0, 1, 1), (0, 1, 1, 1))|0': 0.376425855513308, '((1, 0, 1, 1), (0, 1, 1, 1))|1': 0.44919786096256686, '((0, 1, 0, 1), (1, 0, 1, 1))|0': 0.721120186697783, '((0, 1, 0, 1), (1, 0, 1, 1))|1': 0.7592788971367974, '((0, 1, 1, 0), (1, 0, 0, 1))|0': 0.5577156743620899, '((0, 1, 1, 0), (1, 0, 0, 1))|1': 0.646878198567042, '((1, 0, 0, 1), (1, 0, 0, 0))|0': 0.26953748006379585, '((1, 0, 0, 1), (1, 0, 0, 0))|1': 0.23870417732310314}
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

**Observed (real) value:** 0.0335 (var=0.0005)
**Predicted under pi_6:** 0.0147 (var=0.0003)
**Predicted under pi_4:** 0.0304 (var=0.0003)

### Experiment 7
**Design**
  A=[1, 0, 1, 0]  B=[1, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[1, 0, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  A=[1, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 0, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[0, 1, 1, 1]  B=[1, 1, 1, 0]
  A=[0, 1, 0, 1]  B=[0, 0, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 1, 1, 1]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 0]

**Metric**
```python
P_REF = {'((1, 1, 1, 1), (0, 1, 1, 1))|0': 0.167420814479638, '((1, 1, 1, 1), (0, 1, 1, 1))|1': 0.11561119293078057, '((1, 1, 0, 1), (1, 1, 1, 0))|0': 0.8738938053097345, '((1, 1, 0, 1), (1, 1, 1, 0))|1': 0.8560267857142857, '((0, 0, 0, 1), (0, 0, 1, 1))|0': 0.8552631578947368, '((0, 0, 0, 1), (0, 0, 1, 1))|1': 0.8891369047619048, '((0, 0, 1, 1), (1, 1, 0, 1))|0': 0.8465011286681715, '((0, 0, 1, 1), (1, 1, 0, 1))|1': 0.8732498157700811, '((1, 0, 1, 0), (1, 1, 1, 1))|0': 0.8842105263157894, '((1, 0, 1, 0), (1, 1, 1, 1))|1': 0.8854961832061069, '((1, 0, 1, 0), (0, 1, 0, 1))|0': 0.13548387096774195, '((1, 0, 1, 0), (0, 1, 0, 1))|1': 0.12434456928838951, '((0, 1, 0, 1), (1, 1, 1, 0))|0': 0.8744343891402715, '((0, 1, 0, 1), (1, 1, 1, 0))|1': 0.8700873362445415, '((1, 0, 0, 1), (1, 0, 1, 0))|0': 0.868995633187773, '((1, 0, 0, 1), (1, 0, 1, 0))|1': 0.8688230008984726, '((0, 1, 0, 1), (0, 0, 1, 1))|0': 0.8370044052863436, '((0, 1, 0, 1), (0, 0, 1, 1))|1': 0.8785759694850604, '((0, 1, 1, 1), (1, 1, 1, 0))|0': 0.8617511520737328, '((0, 1, 1, 1), (1, 1, 1, 0))|1': 0.8740849194729137, '((0, 1, 1, 1), (1, 1, 0, 1))|0': 0.8440366972477065, '((0, 1, 1, 1), (1, 1, 0, 1))|1': 0.8868520859671302, '((0, 0, 0, 1), (0, 0, 1, 0))|0': 0.8442265795206971, '((0, 0, 0, 1), (0, 0, 1, 0))|1': 0.8877551020408163, '((0, 1, 0, 1), (1, 0, 0, 1))|0': 0.8174603174603174, '((0, 1, 0, 1), (1, 0, 0, 1))|1': 0.8869509043927648, '((1, 0, 0, 0), (1, 1, 0, 0))|0': 0.8436213991769548, '((1, 0, 0, 0), (1, 1, 0, 0))|1': 0.875951293759513, '((1, 0, 0, 1), (0, 0, 1, 0))|0': 0.12236286919831224, '((1, 0, 0, 1), (0, 0, 1, 0))|1': 0.11068458093410109, '((0, 0, 0, 0), (0, 1, 0, 1))|0': 0.8761261261261262, '((0, 0, 0, 0), (0, 1, 0, 1))|1': 0.8606194690265486}
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

**Observed (real) value:** 0.0021 (var=0.0001)
**Predicted under pi_6:** 0.0027 (var=0.0005)
**Predicted under pi_4:** 0.0029 (var=0.0002)

### Experiment 8
**Design**
  A=[1, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 0]  B=[0, 1, 0, 0]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 0, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 1, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[0, 0, 1, 1]

**Metric**
```python
P_REF = {'((0, 1, 0, 1), (1, 0, 1, 0))|0': 0.8851744186046512, '((0, 1, 0, 1), (1, 0, 1, 0))|1': 0.85431654676259, '((1, 1, 1, 1), (0, 1, 0, 0))|0': 0.138815207780725, '((1, 1, 1, 1), (0, 1, 0, 0))|1': 0.13303437967115098, '((0, 1, 0, 1), (0, 0, 1, 1))|0': 0.7742331288343558, '((0, 1, 0, 1), (0, 0, 1, 1))|1': 0.7372262773722628, '((1, 0, 1, 1), (0, 1, 0, 0))|0': 0.11290959336754836, '((1, 0, 1, 1), (0, 1, 0, 0))|1': 0.14995313964386128, '((1, 1, 1, 1), (1, 0, 1, 1))|0': 0.13828238719068414, '((1, 1, 1, 1), (1, 0, 1, 1))|1': 0.12488769092542677, '((0, 1, 0, 0), (1, 0, 1, 0))|0': 0.8749523446435379, '((0, 1, 0, 0), (1, 0, 1, 0))|1': 0.8515864892528148, '((0, 1, 1, 0), (0, 1, 0, 0))|0': 0.11936339522546419, '((0, 1, 1, 0), (0, 1, 0, 0))|1': 0.14499252615844543, '((1, 0, 1, 0), (0, 1, 1, 0))|0': 0.12627551020408162, '((1, 0, 1, 0), (0, 1, 1, 0))|1': 0.15517241379310345, '((0, 1, 0, 1), (0, 1, 0, 0))|0': 0.13167259786476868, '((0, 1, 0, 1), (0, 1, 0, 0))|1': 0.13609467455621302, '((1, 1, 0, 1), (0, 1, 0, 0))|0': 0.12406417112299466, '((1, 1, 0, 1), (0, 1, 0, 0))|1': 0.13641618497109825, '((1, 0, 1, 0), (0, 1, 0, 0))|0': 0.13288288288288289, '((1, 0, 1, 0), (0, 1, 0, 0))|1': 0.12938596491228072, '((0, 0, 1, 0), (0, 1, 0, 0))|0': 0.24436363636363637, '((0, 0, 1, 0), (0, 1, 0, 0))|1': 0.2447058823529412, '((0, 0, 0, 1), (1, 0, 0, 0))|0': 0.8819255222524978, '((0, 0, 0, 1), (1, 0, 0, 0))|1': 0.8669527896995708, '((0, 0, 1, 0), (1, 1, 0, 0))|0': 0.8461538461538461, '((0, 0, 1, 0), (1, 1, 0, 0))|1': 0.8728323699421965}
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

**Observed (real) value:** 0.0031 (var=0.0001)
**Predicted under pi_6:** 0.0034 (var=0.0002)
**Predicted under pi_4:** 0.0014 (var=0.0001)

### Experiment 9
**Design**
  A=[0, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 0, 1]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 1]  B=[0, 0, 1, 0]
  A=[0, 1, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[0, 0, 0, 0]
  A=[0, 1, 1, 0]  B=[1, 1, 0, 1]
  A=[0, 1, 0, 0]  B=[1, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 0, 1, 0]  B=[1, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 1]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 1, 1]

**Metric**
```python
P_REF = {'((0, 1, 0, 0), (1, 1, 1, 1))|0': 0.8641975308641975, '((0, 1, 0, 0), (1, 1, 1, 1))|1': 0.8896713615023474, '((0, 1, 1, 0), (1, 1, 0, 1))|0': 0.881404174573055, '((0, 1, 1, 0), (1, 1, 0, 1))|1': 0.8806970509383378, '((1, 1, 1, 0), (0, 0, 0, 1))|0': 0.14123006833712984, '((1, 1, 1, 0), (0, 0, 0, 1))|1': 0.1399132321041215, '((0, 0, 0, 0), (1, 1, 0, 0))|0': 0.8642659279778393, '((0, 0, 0, 0), (1, 1, 0, 0))|1': 0.8842398884239888, '((1, 0, 1, 0), (0, 0, 0, 1))|0': 0.12005856515373353, '((1, 0, 1, 0), (0, 0, 0, 1))|1': 0.1336405529953917, '((1, 0, 1, 1), (0, 0, 0, 0))|0': 0.13126843657817108, '((1, 0, 1, 1), (0, 0, 0, 0))|1': 0.12612612612612611, '((1, 0, 1, 0), (0, 1, 0, 1))|0': 0.1225271218889598, '((1, 0, 1, 0), (0, 1, 0, 1))|1': 0.15021459227467812, '((0, 1, 1, 0), (0, 1, 0, 1))|0': 0.11598513011152416, '((0, 1, 1, 0), (0, 1, 0, 1))|1': 0.12307692307692308, '((0, 1, 1, 1), (0, 0, 1, 0))|0': 0.15137254901960784, '((0, 1, 1, 1), (0, 0, 1, 0))|1': 0.17523809523809525, '((1, 0, 0, 1), (0, 1, 0, 0))|0': 0.12048192771084337, '((1, 0, 0, 1), (0, 1, 0, 0))|1': 0.13402061855670103, '((1, 1, 1, 0), (1, 0, 1, 1))|0': 0.29596412556053814, '((1, 1, 1, 0), (1, 0, 1, 1))|1': 0.30364963503649633, '((1, 1, 1, 1), (0, 0, 0, 1))|0': 0.12527716186252771, '((1, 1, 1, 1), (0, 0, 0, 1))|1': 0.11581291759465479, '((1, 1, 0, 1), (0, 0, 1, 1))|0': 0.13, '((1, 1, 0, 1), (0, 0, 1, 1))|1': 0.15555555555555556, '((0, 0, 1, 0), (1, 1, 1, 1))|0': 0.8756841282251759, '((0, 0, 1, 0), (1, 1, 1, 1))|1': 0.8234165067178503, '((0, 1, 0, 0), (1, 1, 0, 1))|0': 0.8695081967213115, '((0, 1, 0, 0), (1, 1, 0, 1))|1': 0.7927272727272727, '((1, 0, 0, 0), (0, 0, 0, 0))|0': 0.13166855845629966, '((1, 0, 0, 0), (0, 0, 0, 0))|1': 0.1501632208922742}
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

**Observed (real) value:** 0.0033 (var=0.0003)
**Predicted under pi_6:** 0.0042 (var=0.0001)
**Predicted under pi_4:** 0.0019 (var=0.0001)

### Experiment 10
**Design**
  A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 1]
  A=[0, 0, 0, 1]  B=[0, 0, 0, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 1, 1]  B=[0, 0, 1, 0]
  A=[0, 1, 1, 1]  B=[1, 1, 1, 0]
  A=[1, 1, 0, 0]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  A=[0, 0, 0, 1]  B=[1, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 0]
  A=[1, 0, 0, 0]  B=[1, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 1, 0, 1]

**Metric**
```python
P_REF = {'((1, 1, 0, 0), (1, 0, 0, 0))|0': 0.11957671957671957, '((1, 1, 0, 0), (1, 0, 0, 0))|1': 0.10058479532163743, '((0, 0, 0, 1), (1, 0, 0, 1))|0': 0.8520084566596194, '((0, 0, 0, 1), (1, 0, 0, 1))|1': 0.8673700075357951, '((1, 1, 1, 1), (0, 0, 0, 1))|0': 0.17372881355932204, '((1, 1, 1, 1), (0, 0, 0, 1))|1': 0.11317135549872123, '((0, 1, 1, 1), (1, 1, 1, 0))|0': 0.8517745302713987, '((0, 1, 1, 1), (1, 1, 1, 0))|1': 0.8652535957607873, '((0, 1, 1, 0), (1, 0, 0, 0))|0': 0.8755555555555555, '((0, 1, 1, 0), (1, 0, 0, 0))|1': 0.8588888888888889, '((0, 0, 0, 1), (1, 1, 1, 0))|0': 0.8913649025069638, '((0, 0, 0, 1), (1, 1, 1, 0))|1': 0.8835489833641405, '((1, 1, 0, 0), (0, 1, 0, 1))|0': 0.11898173768677366, '((1, 1, 0, 0), (0, 1, 0, 1))|1': 0.13608477412158393, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8636871508379889, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8839779005524862, '((1, 0, 0, 0), (1, 1, 1, 0))|0': 0.8688046647230321, '((1, 0, 0, 0), (1, 1, 1, 0))|1': 0.8824057450628366, '((0, 0, 1, 1), (1, 1, 1, 1))|0': 0.8829902491874323, '((0, 0, 1, 1), (1, 1, 1, 1))|1': 0.8688711516533637, '((0, 0, 1, 1), (1, 1, 0, 0))|0': 0.891449814126394, '((0, 0, 1, 1), (1, 1, 0, 0))|1': 0.8813186813186813, '((1, 1, 0, 0), (1, 0, 1, 0))|0': 0.7663716814159292, '((1, 1, 0, 0), (1, 0, 1, 0))|1': 0.7805970149253731, '((0, 0, 0, 0), (1, 1, 1, 1))|0': 0.8597733711048159, '((0, 0, 0, 0), (1, 1, 1, 1))|1': 0.8738574040219378, '((0, 0, 0, 1), (0, 0, 0, 0))|0': 0.15196078431372548, '((0, 0, 0, 1), (0, 0, 0, 0))|1': 0.10185185185185185, '((1, 0, 1, 1), (0, 0, 1, 0))|0': 0.15384615384615385, '((1, 0, 1, 1), (0, 0, 1, 0))|1': 0.12087087087087087}
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

**Observed (real) value:** 0.0029 (var=0.0002)
**Predicted under pi_6:** 0.0083 (var=0.0004)
**Predicted under pi_4:** 0.0009 (var=0.0001)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, Theory 2 (pi_4, Hybrid TTB-Tallying) consistently captures the observed data much better than Theory 1 (pi_6, Validity-Gated Tallying). In Experiment 1, which was proposed by Theory 1, the observed metric on real data (0.0293) strongly diverges from Theory 1's own prediction (0.0010), indicating that Theory 1 fails to accurately predict human behavior even under the conditions it designed. Conversely, in Experiment 2, proposed by Theory 2, the observed data (0.0017) almost perfectly matches Theory 2's prediction (0.0016). Furthermore, Theory 2's predicted metrics closely align with the observed data in the majority of the remaining experiments (e.g., Exps 5, 6, 8, 9, 10). Theory 1's sigmoid-based continuous gating appears to be psychologically implausible or miscalibrated for this binary-feature decision task.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Theory 1 is degenerate as it fails dramatically on its own proposed experiment and generally underperforms Theory 2. Propose a brand-new theory that provides a strong alternative to the deterministic fallback of Theory 2. For instance, consider a Probabilistic Strategy Selection model where individuals do not blend strategies within a trial, but rather probabilistically choose between a purely compensatory strategy (like weighted additive or tallying) and a purely non-compensatory strategy (like Take-The-Best) on each trial, with the probability depending on the dispersion of cue validities or task complexity. Another alternative could be a noisy evidence accumulation model (e.g., a simplified Drift Diffusion Model for binary cues) where cues are sampled sequentially with probability proportional to their validities until a decision threshold is reached."
}
```

## Usage

```json
{
  "prompt_token_count": 26915,
  "candidates_token_count": 418,
  "total_token_count": 28442
}
```
