# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_5" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_5" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_5
Extreme Spatial Bias / Key Perseveration: Subjects completely disengage from the multi-attribute decision task and instead adopt a deterministic response strategy. They choose the exact same option (either always Option A or always Option B) on every single trial, completely ignoring the stimuli and feature validities. The preference for Option A versus Option B is fixed per subject, creating a population split between 'Always-A' and 'Always-B' responders. At the individual level, the choice policy is entirely deterministic and repetitive.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    # The subject adopts a deterministic response strategy, always choosing the same option.
    pref = int(parameters["preferred_option"])
    if pref == 0:
        return np.array([1.0, 0.0])
    else:
        return np.array([0.0, 1.0])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

## THEORY 2 — pi_3
Decision-makers use a Weighted Additive (WADD) strategy, integrating all available features weighted by their validities, but they are subject to significant spatial/positional biases (e.g., a baseline preference for Option A over Option B) and high levels of task disengagement (lapse rate). In environments where subjects ignore features, the positional bias and lapse rate dominate the choice, leading to choices that appear completely orthogonal to standard heuristic predictions like TTB or Tallying (yielding exact 0.5 consistency).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Weighted Additive (WADD) scores
    score_a = np.sum(val * a)
    score_b = np.sum(val * b)
    
    beta = float(parameters["beta"])
    bias_a = float(parameters["bias_A"])
    epsilon = float(parameters["epsilon"])
    
    # Incorporate spatial/positional bias for Option A
    logits = np.array([beta * score_a + bias_a, beta * score_b])
    
    # Numerically stable softmax
    logits = logits - np.max(logits)
    p_core = np.exp(logits) / np.sum(np.exp(logits))
    
    # Apply lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))

## EXPERIMENT 1 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 6: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]

**Rationale:** To quantitatively dissociate the Advocated Theory (Extreme Spatial Bias / Key Perseveration) from the Competing Theory (WADD with spatial bias and lapse rate), this design introduces extreme variations in the objective quality (weighted feature sum) between Option A and Option B across trials. The Advocated Theory predicts that an individual subject will rigidly choose the exact same option (either 100% A or 100% B) on every single trial, completely ignoring the stimulus features. In contrast, the Competing Theory predicts that unless the subject is completely insensitive to the stimuli (beta=0), their probability of choosing Option A will systematically vary according to the difference in weighted additive scores between the options. By including trials where Option A strongly dominates Option B, trials where Option B strongly dominates Option A, and mixed compensatory trials, we can cleanly separate individuals who are merely biased but still integrating features (Competing Theory) from those who are entirely perseverative and stimulus-blind (Advocated Theory).

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
The Advocated theory predicts that subjects will deterministically choose the exact same option on every single trial (either 100% A or 100% B). Thus, the proportion of their most frequent choice should be exactly 1.0 for every subject. The Competing theory predicts that subjects will vary their choices based on the stimulus features (WADD) or exhibit lapse rates, leading to a majority choice proportion strictly less than 1.0. By calculating the average across subjects of their individual majority choice proportions, we obtain a metric that is exactly 1.0 with 0 variance under the Advocated theory, but significantly lower under the Competing theory.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    subject_means = data.groupby('subject_id')['response'].mean()
    majority_props = np.maximum(subject_means, 1.0 - subject_means)
    return float(majority_props.mean())

### RESULTS
- Predicted under pi_5 (simulated): 1.0000 (var=0.0000)
- Predicted under pi_3 (simulated): 0.7040 (var=0.0167)
- Observed on real data: 1.0000 (var=0.0000)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  trial 3: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 5: A=[1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1]
  trial 6: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 7: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 8: A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]

**Rationale:** To quantitatively dissociate the Advocated Theory (WADD with spatial bias and lapse rate) from the Competing Theory (Extreme Spatial Bias / Key Perseveration), this design introduces extreme variations in the objective quality (weighted feature sum) between Option A and Option B across trials. The Competing Theory rigidly predicts that an individual subject will deterministically choose the exact same option (either 100% A or 100% B) on every single trial, completely ignoring the stimulus features. In contrast, the Advocated Theory predicts that unless the subject is completely insensitive to the stimuli (beta=0), their probability of choosing Option A will systematically vary according to the difference in weighted additive scores between the options. By including trials where Option A strongly dominates Option B, trials where Option B strongly dominates Option A, mixed compensatory trials, and tie trials, we can cleanly separate individuals who are merely biased but still integrating features (Advocated Theory) from those who are entirely perseverative and stimulus-blind (Competing Theory).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
The Competing Theory predicts that every subject adopts a deterministic, stimulus-blind strategy where they choose the exact same option on every trial (100% A or 100% B). Therefore, the proportion of their less frequent choice will be exactly 0. The Advocated Theory models choice as a probabilistic process driven by weighted additive scores, spatial bias, and a lapse rate. Even with extreme spatial biases, the lapse rate and varying stimulus qualities will induce some switching, resulting in a non-zero proportion of the less frequent choice. This metric captures the average within-subject deviation from a pure 'always A' or 'always B' strategy.

Source:
def metric(data: pd.DataFrame) -> float:
    # Calculate the mean response (proportion of B choices) for each subject
    subj_means = data.groupby('subject_id')['response'].mean()
    # Find the proportion of the less frequent choice for each subject
    # Under the Competing Theory, subjects always choose A (0) or B (1), so this is exactly 0.0
    # Under the Advocated Theory, due to lapse rates and stimulus sensitivity, this will be > 0.0
    min_prop = subj_means.apply(lambda x: min(x, 1.0 - x))
    return float(min_prop.mean())

### RESULTS
- Predicted under pi_5 (simulated): 0.0000 (var=0.0000)
- Predicted under pi_3 (simulated): 0.3192 (var=0.0173)
- Observed on real data: 0.0000 (var=0.0000)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_preds = []
    for a, b in zip(data['option_a_ratings'], data['option_b_ratings']):
        pred = 0.5
        for i in range(len(a)):
            if a[i] > b[i]:
                pred = 0
                break
            elif b[i] > a[i]:
                pred = 1
                break
        ttb_preds.append(pred)
        
    ttb_preds = np.array(ttb_preds)
    responses = data['response'].values
    
    return float(np.mean(ttb_preds == responses))
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5000 (var=0.0000)
**Predicted under pi_3:** 0.4029 (var=0.0166)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Extract option ratings into 2D numpy arrays
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    # Calculate number of feature-wise wins for each option
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    responses = data['response'].values
    
    # Identify trials where Tallying has a strict preference
    tally_prefers_a = a_wins > b_wins
    tally_prefers_b = b_wins > a_wins
    
    # Check if subject's response is consistent with Tallying's preference
    consistent = (tally_prefers_a & (responses == 0)) | (tally_prefers_b & (responses == 1))
    strict_trials = tally_prefers_a | tally_prefers_b
    
    if np.sum(strict_trials) == 0:
        return 0.5
        
    # Return the proportion of Tallying-consistent choices on strict trials
    return float(np.sum(consistent[strict_trials]) / np.sum(strict_trials))
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5000 (var=0.0000)
**Predicted under pi_3:** 0.5791 (var=0.0214)

### Experiment 5
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.75, 0.65, 0.55])
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    # TTB predictions
    diff = a_mat - b_mat
    ttb_preds = np.zeros(len(data))
    for i in range(len(data)):
        for j in range(4):
            if diff[i, j] > 0:
                ttb_preds[i] = 0
                break
            elif diff[i, j] < 0:
                ttb_preds[i] = 1
                break
                
    # WADD predictions (without spatial bias)
    score_a = a_mat @ validities
    score_b = b_mat @ validities
    wadd_preds = (score_b > score_a).astype(int)
    
    # Isolate trials where TTB and WADD (unbiased) predict opposite choices
    mask = ttb_preds != wadd_preds
    
    if not np.any(mask):
        return 0.5
        
    responses = data['response'].values
    agreement = (responses[mask] == ttb_preds[mask]).mean()
    return float(agreement)
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5000 (var=0.0000)
**Predicted under pi_3:** 0.4614 (var=0.0072)

### Experiment 6
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 0, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_t1(row):
        return tuple(int(x) for x in row['option_a_ratings']) == (0, 1, 1, 1) and \
               tuple(int(x) for x in row['option_b_ratings']) == (1, 0, 0, 0)
               
    def is_t2(row):
        return tuple(int(x) for x in row['option_a_ratings']) == (1, 0, 0, 0) and \
               tuple(int(x) for x in row['option_b_ratings']) == (0, 1, 1, 1)
               
    t1_mask = data.apply(is_t1, axis=1)
    t2_mask = data.apply(is_t2, axis=1)
    
    t1_data = data[t1_mask]
    t2_data = data[t2_mask]
    
    p_a_t1 = (t1_data['response'] == 0).mean() if len(t1_data) > 0 else 0.5
    p_a_t2 = (t2_data['response'] == 0).mean() if len(t2_data) > 0 else 0.5
    
    return float(p_a_t1 - p_a_t2)
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Predicted under pi_5:** 0.0000 (var=0.0000)
**Predicted under pi_3:** 0.1400 (var=0.0701)

### Experiment 7
**Design**
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[1, 1, 1, 1]
  A=[1, 0, 1, 0]  B=[1, 0, 1, 0]
  A=[0, 1, 0, 1]  B=[0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate sum of ratings for A and B
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Identify trials where A has more positive features than B, and vice versa
    a_dom = (sum_a > sum_b)
    b_dom = (sum_a < sum_b)
    
    # Proportion of choosing A (response == 0)
    p_a_given_a_dom = (data.loc[a_dom, 'response'] == 0).mean()
    p_a_given_b_dom = (data.loc[b_dom, 'response'] == 0).mean()
    
    if np.isnan(p_a_given_a_dom):
        p_a_given_a_dom = 0.5
    if np.isnan(p_a_given_b_dom):
        p_a_given_b_dom = 0.5
        
    return float(p_a_given_a_dom - p_a_given_b_dom)
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Predicted under pi_5:** 0.0000 (var=0.0000)
**Predicted under pi_3:** 0.1700 (var=0.1160)

### Experiment 8
**Design**
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[1, 0, 1, 0]
  A=[0, 1, 0, 1]  B=[0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    df = data.copy()
    # Convert responses to 1 if Option A was chosen, 0 otherwise
    df['is_A'] = (df['response'] == 0).astype(float)
    
    # Create a hashable string representation for each unique trial type
    df['trial_type'] = df['option_a_ratings'].apply(lambda x: ''.join(map(str, x))) + "_" + \
                       df['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Calculate the proportion of times Option A was chosen for each trial type, per subject
    subj_trial_means = df.groupby(['subject_id', 'trial_type'])['is_A'].mean()
    
    # Calculate the squared deviation from 0.5 (random guessing baseline)
    sq_dev = (subj_trial_means - 0.5) ** 2
    
    # Average these squared deviations across trial types for each subject
    subj_scores = sq_dev.groupby('subject_id').mean()
    
    # Return the mean across all subjects
    return float(subj_scores.mean())
```

**Observed (real) value:** 0.2500 (var=0.0000)
**Predicted under pi_5:** 0.2500 (var=0.0000)
**Predicted under pi_3:** 0.0813 (var=0.0035)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all eight experiments, Theory 1 (Extreme Spatial Bias / Key Perseveration) perfectly predicts the observed data, whereas Theory 2 (WADD with spatial bias and lapse rate) consistently fails. The observed metrics exactly match the predictions of a completely deterministic, stimulus-blind response strategy where subjects choose the exact same option on every single trial (e.g., Exp 1 majority proportion is exactly 1.0, Exp 2 less frequent choice proportion is exactly 0.0, Exp 8 squared deviation is exactly 0.25). Theory 2's assumption that subjects integrate features to some degree and have a lapse rate cannot account for this extreme level of perseveration. Since Theory 1 is already a perfect fit, Theory 2 should be replaced with a brand-new theory that acts as a strong, philosophically distinct competitor to Theory 1's 'pure spatial bias' explanation.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'First-Trial Inertia' or 'Rational Disengagement' theory. Instead of assuming subjects have an a priori spatial bias (as in Theory 1), this theory should posit that subjects actually evaluate the very first trial using a simple heuristic (like TTB or Tallying) to make an initial choice. However, because the task provides no trial-by-trial feedback and features are equally complex, subjects rationally disengage after the first trial and simply repeat their initial motor action for the remainder of the experiment to minimize cognitive effort. This provides a different mechanistic origin for the observed 100% perseveration."
}
```

## Usage

```json
{
  "prompt_token_count": 7257,
  "candidates_token_count": 352,
  "total_token_count": 8673
}
```
