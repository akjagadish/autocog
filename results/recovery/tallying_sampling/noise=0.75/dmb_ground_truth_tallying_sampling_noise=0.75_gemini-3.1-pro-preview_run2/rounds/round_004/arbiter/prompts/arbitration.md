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
Environment-Adaptive Strategy Selection Model (TTB vs. Tallying). Decision-makers probabilistically choose between a non-compensatory strategy (Take-The-Best) and a compensatory strategy (Tallying) on a trial-by-trial basis. Crucially, the probability of deploying TTB is not fixed but adapts to the structure of the environment: it is a logistic function of the dispersion (standard deviation) of the cue validities. In environments with steep validity gradients (high dispersion), TTB is strongly preferred; in environments with flat gradients (low dispersion), decision-makers naturally fall back to Tallying.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    validities = np.asarray(parameters["validities"], dtype=float)
    
    dispersion = np.std(validities)
    slope = float(parameters["disp_slope"])
    threshold = float(parameters["disp_threshold"])
    
    # Calculate w_ttb dynamically based on the dispersion of cue validities
    w_ttb = 1.0 / (1.0 + np.exp(-slope * (dispersion - threshold)))
    
    beta_tally = float(parameters["beta_tally"])
    epsilon = float(parameters["epsilon"])
    
    # --- TTB Strategy ---
    # Sort cues by validity (descending)
    # We add a tiny amount of noise to validities to break ties consistently if they exist
    order = np.argsort(-(validities + np.random.uniform(0, 1e-6, size=len(validities))))
    
    p_ttb = np.array([0.5, 0.5])
    for idx in order:
        if stim[0, idx] > stim[1, idx]:
            p_ttb = np.array([1.0, 0.0])
            break
        elif stim[1, idx] > stim[0, idx]:
            p_ttb = np.array([0.0, 1.0])
            break
            
    # --- Tallying Strategy ---
    scores = np.sum(stim, axis=1)
    z = beta_tally * scores
    z = z - np.max(z)
    e = np.exp(z)
    p_tally = e / np.sum(e)
    
    # --- Mixture ---
    p_core = w_ttb * p_ttb + (1.0 - w_ttb) * p_tally
    
    # --- Lapse ---
    n_opts = len(p_core)
    p_final = (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
    
    return p_final

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

## THEORY 2 — pi_4
Probabilistic Search Take-The-Best (PS-TTB)

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    diff = stim[0] - stim[1]
    
    validities = np.asarray(parameters['validities'], dtype=float)
    tau = float(parameters['tau'])
    epsilon = float(parameters['epsilon'])
    
    n_features = len(validities)
    n_samples = 1000
    
    # Gumbel-max trick to sample permutations without replacement
    # probabilities proportional to softmax(validities / tau)
    logits = validities / (tau + 1e-6)
    gumbels = np.random.gumbel(size=(n_samples, n_features))
    orders = np.argsort(-(logits + gumbels), axis=1)
    
    diff_sign = np.sign(diff)
    ordered_diffs = diff_sign[orders]
    
    # Find the first discriminating cue in each sampled search order
    abs_diffs = np.abs(ordered_diffs)
    first_non_zero_idx = np.argmax(abs_diffs, axis=1)
    has_non_zero = np.any(abs_diffs > 0, axis=1)
    
    first_non_zero_vals = ordered_diffs[np.arange(n_samples), first_non_zero_idx]
    
    wins_a = np.sum((first_non_zero_vals == 1) & has_non_zero)
    wins_b = np.sum((first_non_zero_vals == -1) & has_non_zero)
    
    total = wins_a + wins_b
    if total > 0:
        p = np.array([wins_a / total, wins_b / total])
    else:
        p = np.array([0.5, 0.5])
        
    return (1.0 - epsilon) * p + epsilon * (np.ones(2) / 2.0)

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

## EXPERIMENT 1 (proposed by pi_6)

### DESIGN
**Validities (n_features=5):** [0.92, 0.89, 0.86, 0.83, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 7: A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  trial 8: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** To cleanly dissociate the Environment-Adaptive Strategy Selection Model (EASSM) from Probabilistic Search Take-The-Best (PS-TTB), we use a 5-feature design with a cluster of high validities and one low validity. This creates a low-dispersion environment where EASSM heavily weights Tallying, but strict TTB still acts as a tie-breaker. In 'tied-tally' trials (e.g., A has cue 1 and 5; B has cues 2 and 3), EASSM relies on its TTB component and strictly favors the option with the single highest validity cue (Option A). In contrast, PS-TTB probabilistically samples cues based on validity; because cues 1, 2, and 3 have very similar validities, PS-TTB is more likely to sample one of B's two highly valid cues before A's single highly valid cue, leading PS-TTB to favor Option B. This creates a strong qualitative dissociation.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric leverages a mathematically guaranteed invariant in the Environment-Adaptive Strategy Selection Model (EASSM) that is systematically violated by Probabilistic Search Take-The-Best (PS-TTB). In EASSM, Trial 4 and Trial 6 both yield a Tallying score difference of -1, while Trial 7 and Trial 8 yield a Tallying score difference of +1. Simultaneously, TTB strictly favors Option A in T4 and T7, and Option B in T6 and T8. When combining these four trials into the contrast `P(A|T4) + P(A|T8) - P(A|T6) - P(A|T7)`, the linear mixture of TTB and Tallying perfectly cancels out both the mixture weight `w` and the specific logistic tallying probabilities. Thus, EASSM structurally guarantees this contrast evaluates to exactly 0.0 across its entire parameter space, with variance reduced to the theoretical minimum of binomial sampling noise.

In contrast, PS-TTB searches cues probabilistically based on their validities. Because the validity gradient is steep at the top (cue 1 is 0.92) but drops sharply at the bottom (cue 5 is 0.5), PS-TTB evaluates these trials asymmetrically. The sum of the validity differences heavily favors Option A in this specific linear combination. Consequently, PS-TTB predicts a strictly positive value for this contrast across all values of tau, peaking strongly at intermediate tau. This provides a robust, zero-variance baseline for EASSM against a structurally positive signal for PS-TTB, ensuring a highly significant qualitative dissociation.

Source:
def metric(data: pd.DataFrame) -> float:
    # Isolate the relevant trials
    t4_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
    t8_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 1, 1, 1, 0)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 0, 1))
    t6_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 0, 1, 1)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 1, 0, 0))
    t7_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 1, 1, 0)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 1, 0, 0, 1))
    
    t4_data = data[t4_mask]
    t8_data = data[t8_mask]
    t6_data = data[t6_mask]
    t7_data = data[t7_mask]
    
    if len(t4_data) == 0 or len(t8_data) == 0 or len(t6_data) == 0 or len(t7_data) == 0:
        return 0.0
        
    p_a_t4 = (t4_data['response'] == 0).mean()
    p_a_t8 = (t8_data['response'] == 0).mean()
    p_a_t6 = (t6_data['response'] == 0).mean()
    p_a_t7 = (t7_data['response'] == 0).mean()
    
    # The structural contrast
    return float(p_a_t4 + p_a_t8 - p_a_t6 - p_a_t7)

### RESULTS
- Predicted under pi_6 (simulated): -0.0483 (var=0.0728)
- Predicted under pi_4 (simulated): -0.0117 (var=0.0717)
- Observed on real data: 0.0100 (var=0.0652)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.92, 0.9, 0.88, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  trial 3: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0]
  trial 4: A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 1]
  trial 5: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 7: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 8: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Rationale:** To quantitatively and qualitatively dissociate Probabilistic Search Take-The-Best (PS-TTB) from the Environment-Adaptive Strategy Selection Model (EASSM), we exploit how each theory handles ties in a compensatory (Tallying) context. EASSM is a mixture of Tallying and strict TTB. In trials where both options have the same number of positive features (Tallying is indifferent), EASSM will break the tie using its strict TTB component, which deterministically favors the option with the single highest-validity discriminating cue. In contrast, PS-TTB samples cue search orders probabilistically based on validities. By creating a cluster of three high-validity cues (e.g., 0.92, 0.90, 0.88), we can design 'conflict' trials where Option A is favored by the single highest-validity cue (Cue 1), but Option B is favored by the next two high-validity cues (Cues 2 and 3). Because the validities are very close, PS-TTB is highly likely to sample Cue 2 or Cue 3 before Cue 1, leading it to favor Option B. Meanwhile, EASSM will strictly favor Option A (since Tallying is tied and strict TTB chooses A). This yields a powerful qualitative dissociation (EASSM predicts P(A) > 0.5, while PS-TTB predicts P(A) < 0.5).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times the subject chooses the option favored by the single highest-validity cue (Cue 1) on 'conflict' trials. Conflict trials are specifically those where Tallying is tied, Cue 1 favors one option, and the next two high-validity cues (Cues 2 and 3) favor the alternative option. Under EASSM, the tie in Tallying causes the model to rely on its strict TTB component, which deterministically chooses the option favored by Cue 1 (yielding a metric close to 1.0). In contrast, PS-TTB searches cues probabilistically; because Cues 2 and 3 also have very high validities, PS-TTB is highly likely to encounter one of them before Cue 1, leading it to favor the alternative option (yielding a metric well below 0.5). This creates a massive, robust qualitative dissociation between the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    cue1_chosen = []
    for _, row in data.iterrows():
        A = row['option_a_ratings']
        B = row['option_b_ratings']
        resp = row['response']
        
        # Check if it's a conflict trial where Cue 1 favors one option,
        # and Cues 2 and 3 favor the other option.
        if A[0] != B[0] and A[1] != B[1] and A[2] != B[2]:
            if A[0] != A[1] and A[0] != A[2]:
                # Conflict trial identified
                if A[0] > B[0]:
                    # Cue 1 favors Option A
                    cue1_chosen.append(1 if resp == 0 else 0)
                else:
                    # Cue 1 favors Option B
                    cue1_chosen.append(1 if resp == 1 else 0)
                    
    if len(cue1_chosen) == 0:
        return 0.5
    return float(np.mean(cue1_chosen))

### RESULTS
- Predicted under pi_6 (simulated): 0.5825 (var=0.0185)
- Predicted under pi_4 (simulated): 0.4883 (var=0.0051)
- Observed on real data: 0.4717 (var=0.0057)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_0 = data['option_a_ratings'].apply(lambda x: x[0])
    b_0 = data['option_b_ratings'].apply(lambda x: x[0])
    ttb_choice = np.where(b_0 > a_0, 1, 0)
    return float(np.mean(data['response'] == ttb_choice))
```

**Observed (real) value:** 0.4550 (var=0.0021)
**Predicted under pi_6:** 0.4990 (var=0.0266)
**Predicted under pi_4:** 0.4452 (var=0.0026)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.95, 0.75, 0.65, 0.55])
    
    def is_ttb_match(row):
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # TTB prediction
        ttb_winner = None
        for i in range(4):
            if a[i] > b[i]:
                ttb_winner = 0
                break
            elif b[i] > a[i]:
                ttb_winner = 1
                break
                
        # WADD expected prediction (assuming uniform weights)
        wadd_a = np.sum(a * validities)
        wadd_b = np.sum(b * validities)
        wadd_winner = 0 if wadd_a > wadd_b else 1
        
        # Only consider compensatory trials where the models disagree
        if ttb_winner is not None and ttb_winner != wadd_winner:
            return 1.0 if row['response'] == ttb_winner else 0.0
        return np.nan

    matches = data.apply(is_ttb_match, axis=1)
    return float(matches.mean())
```

**Observed (real) value:** 0.4225 (var=0.0057)
**Predicted under pi_6:** 0.4083 (var=0.0327)
**Predicted under pi_4:** 0.3950 (var=0.0059)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    def is_11000(x):
        return tuple(x) == (1, 1, 0, 0, 0)
    
    def is_00111(x):
        return tuple(x) == (0, 0, 1, 1, 1)
        
    a_11000 = data['option_a_ratings'].apply(is_11000)
    b_00111 = data['option_b_ratings'].apply(is_00111)
    
    a_00111 = data['option_a_ratings'].apply(is_00111)
    b_11000 = data['option_b_ratings'].apply(is_11000)
    
    t1 = a_11000 & b_00111
    t3 = a_00111 & b_11000
    
    chose_11000 = (t1 & (data['response'] == 0)) | (t3 & (data['response'] == 1))
    
    relevant = t1 | t3
    if relevant.sum() == 0:
        return 0.5
    return float(chose_11000.sum() / relevant.sum())
```

**Observed (real) value:** 0.4183 (var=0.0241)
**Predicted under pi_6:** 0.4408 (var=0.0350)
**Predicted under pi_4:** 0.4542 (var=0.0118)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_target_trial(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        # Target trials where WADD and Tallying strictly disagree
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            return True
        if a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            return True
        return False

    mask = data.apply(is_target_trial, axis=1)
    target_data = data[mask]
    
    if len(target_data) == 0:
        return 0.5
        
    sum_a = target_data['option_a_ratings'].apply(sum)
    sum_b = target_data['option_b_ratings'].apply(sum)
    
    # Calculate how often the subject chose the option with MORE positive features (Tallying's preference)
    chose_more = ((target_data['response'] == 0) & (sum_a > sum_b)) | \
                 ((target_data['response'] == 1) & (sum_b > sum_a))
                 
    return float(chose_more.mean())
```

**Observed (real) value:** 0.5867 (var=0.0125)
**Predicted under pi_6:** 0.5417 (var=0.0547)
**Predicted under pi_4:** 0.5675 (var=0.0095)

### Experiment 7
**Design**
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    A_ratings = np.stack(data['option_a_ratings'].values)
    B_ratings = np.stack(data['option_b_ratings'].values)
    
    sum_A = A_ratings.sum(axis=1)
    sum_B = B_ratings.sum(axis=1)
    
    # Identify all trials where the difference in total positive features is exactly 1.
    # These are T1, T5, T6, and T7.
    diff_1_mask = np.abs(sum_A - sum_B) == 1
    
    if not np.any(diff_1_mask):
        return 0.5
        
    data_diff1 = data[diff_1_mask]
    sum_A_diff1 = sum_A[diff_1_mask]
    sum_B_diff1 = sum_B[diff_1_mask]
    responses = data_diff1['response'].values
    
    # 1 if the subject chose the option with the higher total number of positive features, 0 otherwise
    chose_higher = np.where(sum_A_diff1 > sum_B_diff1, responses == 0, responses == 1)
    
    return float(np.mean(chose_higher))
```

**Observed (real) value:** 0.6117 (var=0.0051)
**Predicted under pi_6:** 0.6400 (var=0.0163)
**Predicted under pi_4:** 0.5617 (var=0.0039)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate the sum of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Isolate trials where the feature sums differ (diff > 0)
    mask = sum_a != sum_b
    if not mask.any():
        return 0.5
        
    valid_data = data[mask].copy()
    
    # Determine the 'majority' option (0 for A, 1 for B)
    maj_choice = (sum_a[mask] < sum_b[mask]).astype(int)
    
    # Check if the subject chose the majority option
    valid_data['is_maj'] = (valid_data['response'] == maj_choice).astype(float)
    
    # Calculate the overall accuracy relative to the feature sum per subject
    subj_acc = valid_data.groupby('subject_id')['is_maj'].mean()
    
    # Apply a smooth sigmoid centered at 0.75.
    # Tallying uses a logistic link function, routinely producing choice accuracies > 0.80 
    # when beta is moderate/high and epsilon is low. 
    # PS-TTB with tau > 1 (99% of its parameter space) behaves identically to Random Search,
    # whose theoretical maximum accuracy on these trials is capped exactly at ~0.716.
    # A smooth slope (12.0) prevents the variance from exploding (unlike steep thresholds or high powers),
    # while cleanly separating the dense right tail of Tallying from the bounded distribution of PS-TTB.
    score = 1.0 / (1.0 + np.exp(-12.0 * (subj_acc - 0.75)))
    
    return float(score.mean())
```

**Observed (real) value:** 0.1432 (var=0.0027)
**Predicted under pi_6:** 0.2658 (var=0.0773)
**Predicted under pi_4:** 0.1988 (var=0.0196)

### Experiment 9
**Design**
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Trial 1: A=[0, 1, 1, 1, 1, 1], B=[1, 0, 0, 0, 0, 0]
    # Trial 2: A=[1, 0, 0, 1, 1, 1], B=[0, 1, 1, 0, 0, 0]
    def is_t1(row):
        return tuple(int(v) for v in row['option_a_ratings']) == (0, 1, 1, 1, 1, 1) and \
               tuple(int(v) for v in row['option_b_ratings']) == (1, 0, 0, 0, 0, 0)
    def is_t2(row):
        return tuple(int(v) for v in row['option_a_ratings']) == (1, 0, 0, 1, 1, 1) and \
               tuple(int(v) for v in row['option_b_ratings']) == (0, 1, 1, 0, 0, 0)
    
    mask_t1 = data.apply(is_t1, axis=1)
    mask_t2 = data.apply(is_t2, axis=1)
    
    p_b_t1 = float(data[mask_t1]['response'].mean()) if mask_t1.any() else 0.5
    p_b_t2 = float(data[mask_t2]['response'].mean()) if mask_t2.any() else 0.5
    
    return p_b_t1 - p_b_t2
```

**Observed (real) value:** -0.0067 (var=0.0494)
**Predicted under pi_6:** 0.0500 (var=0.0569)
**Predicted under pi_4:** -0.0550 (var=0.0418)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    a_str = data['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    
    def p_target(target_a, target_b):
        m_straight = (a_str == target_a) & (b_str == target_b)
        m_swap = (a_str == target_b) & (b_str == target_a)
        
        n_straight = m_straight.sum()
        n_swap = m_swap.sum()
        
        if n_straight + n_swap == 0:
            return 0.5
            
        wins = 0
        if n_straight > 0:
            wins += (data.loc[m_straight, 'response'] == 0).sum()
        if n_swap > 0:
            wins += (data.loc[m_swap, 'response'] == 1).sum()
            
        return float(wins / (n_straight + n_swap))
        
    # Trial 1: Target A = 10000, Target B = 01110
    p_t1 = p_target("10000", "01110")
    
    # Trial 7: Target A = 10110, Target B = 01001
    p_t7 = p_target("10110", "01001")
    
    return float(p_t7 - p_t1)
```

**Observed (real) value:** 0.1933 (var=0.0443)
**Predicted under pi_6:** 0.3117 (var=0.0894)
**Predicted under pi_4:** 0.1567 (var=0.0657)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the 10 experiments, Theory 2 (PS-TTB) generally outperforms Theory 1 (EASSM). In the critical dissociations (Experiments 1 and 2), PS-TTB's predictions align much closer with the observed data. For instance, in Experiment 2, EASSM predicts a metric > 0.5 due to its deterministic tie-breaking via strict TTB, whereas PS-TTB correctly predicts the metric will be < 0.5 (observed 0.4717), reflecting probabilistic sampling of highly valid cues. However, PS-TTB still misses the mark on some experiments (e.g., Exp 7, Exp 9), suggesting that neither theory perfectly captures the underlying compensatory mechanisms. EASSM's rigid switching between strict TTB and Tallying fails to capture the nuances of human decision-making in these environments.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace the Environment-Adaptive Strategy Selection Model (EASSM) with a 'Stochastic Weighted Additive Model' (SWADD) or a 'Sequential Cue Accumulation Model'. Unlike EASSM, which rigidly switches between strict TTB and Tallying, and PS-TTB, which relies on non-compensatory stopping rules, the new theory should assume that decision-makers integrate all available cues but weight them proportionally to their validities (or a transformed version of validities). To account for bounded rationality and variability, the model should incorporate decision noise (e.g., via a softmax choice rule over the weighted sums) and potentially a lapse rate. This compensatory but noisy integration can naturally account for both the probabilistic nature of choices and the sensitivity to multiple high-validity cues that PS-TTB captures, while providing a more robust fit across varied environments."
}
```

## Usage

```json
{
  "prompt_token_count": 10763,
  "candidates_token_count": 400,
  "total_token_count": 12220
}
```
