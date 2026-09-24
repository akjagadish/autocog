# Round 1 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** People use a validity-graded compensatory integration rule. On every choice they inspect all features, compute a signed option advantage by summing each discriminating feature's contribution, and then choose via a softmax over that advantage plus an independent lapse. Unlike Take The Best there is no early stopping. Unlike pure Tallying, each feature's contribution is weighted by a validity-sensitive multiplier. The multiplier is anchored around equal weighting, w_j = 1 + kappa * (v_j - mean(v)), normalized so the average weight is exactly 1. Because kappa has a symmetric prior centered at zero, the population-level expected weight vector is the equal-weight vector, but individual subjects may slightly overweight or underweight higher-validity cues. Tied features contribute nothing.

**Rationale:** This theory replaces pi_1's one-reason stopping rule with full compensatory integration, so it does not wrongly commit to the first discriminating cue. In Experiment 1, that matters because the five lower-validity features can jointly outweigh the single high-validity feature, and in Experiment 2 signed evidence across the full feature vector must drive choice. The model also differs from plain Tallying by allowing feature weights to be validity-graded through kappa. The kappa prior is symmetric around zero and small, so the population-level expected weight vector is exactly the equal-weight vector, which captures the fact that both observed experiments sit close to ordinary Tallying while still giving the theory a substantive validity-weighting mechanism.

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`
  - `kappa`: `[-0.10, 0.10]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
import numpy as np

def predict(parameters, state, history):
    # Validity-graded compensatory integration.
    # state is the current pair of option feature vectors, shape (2, n_features).
    # Row 0 = option A, row 1 = option B. History is irrelevant because there is
    # no trial-by-trial feedback and the rule is applied independently each trial.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Validity-graded integration expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    validities = np.asarray(parameters["validities"], dtype=float)
    n_features = stim.shape[1]
    if validities.shape[0] != n_features:
        raise ValueError(
            f"validities length {validities.shape[0]} != n_features {n_features}."
        )

    # Validity-sensitive weights around a strict equal-weight anchor.
    # The centered validities sum to zero, so the raw weights sum to n_features.
    # Normalizing by their mean keeps the scale of the advantage score directly
    # comparable to an unweighted signed tally when kappa is small.
    kappa = float(parameters["kappa"])
    centered_validities = validities - np.mean(validities)
    weights = 1.0 + kappa * centered_validities
    weights = weights / np.mean(weights)

    # Discriminating features contribute according to their weights; ties
    # have difference zero and thus contribute nothing.
    advantage = float(np.dot(weights, stim[0] - stim[1]))

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Stable softmax over the signed advantage versus a zero-advantage boundary.
    # This reduces to logistic choice in the weighted advantage.
    scores = np.array([advantage, 0.0])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)

    n_opts = 2
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
import numpy as np

def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


### slot 2 — `pi_2` — KILLED ✗

**Description:** People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


**Rationale:** (none)

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, stimulus, history):
    # Paper-faithful Tallying heuristic (Dawes 1979; Gigerenzer &
    # Goldstein 1999). Stimulus is the pair of option feature vectors
    # for the current trial: array-like of shape (2, n_features),
    # with row 0 = option A, row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    # Count strict feature-wise wins; ties contribute to neither option.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. When
    # a_wins == b_wins the softmax is exactly uniform regardless of
    # beta, which is the correct behavior for an undiscriminating
    # tally.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)
```


## Replacement

### `pi_4` → slot 2 (via `new_theory`)

**Description:** People use a validity-gated tallying rule. On every trial they first compute the unweighted tally difference d = #A wins - #B wins. If the tallies clearly differ, choice is driven by a softmax over the two unweighted tallies, exactly as in Tallying, so majority-tally behavior is preserved. Only when the tallies are tied, or within a small threshold tau of tied, is communicated validity used: the decision maker computes validity-weighted evidence V = sum_j w_j * (A_j - B_j), with weights w_j = (v_j - 0.5)^gamma increasing steeply and convexly in validity. Choice on these tie trials is then a separate softmax over V and -V, with its own inverse temperature beta_v and lapse epsilon_v, and with probability 1 - fallback_p the subject simply guesses instead of using this validity fallback. Thus validity does not continuously reweight every trial, as in a compensatory rule, nor are ties resolved by blind guessing, as in Tallying.

**Rationale:** This theory follows the arbiter's prescribed two-branch architecture. On unequal tallies it uses unweighted tallying with the same softmax/lapse machinery as pi_2, which preserves the majority-tally behavior needed for the unequal-count trials. On tally ties it uses validity-weighted evidence rather than guessing, so it can produce the large tie-trial validity effects seen in Experiments 3 and 4. Crucially, the tie fallback is not deterministic: beta_v, epsilon_v, and fallback_p introduce graded fallback use, avoiding the deterministic sign-of-V overshoot in Experiment 4. The convex weight function w_j = (v_j - 0.5)^gamma strongly attenuates cues near chance validity, so the fallback is weak in designs where the high-validity cues are only moderately separated, but is strong when communicated validities produce large weighted evidence differences. This is the key mechanistic difference from pi_2, which guesses on ties, and from pi_3, which lets validity reweight every trial continuously.

**Parameters:**
  - `beta_tally`: `[0.1, 20.0]`
  - `epsilon_tally`: `[0.0, 0.5]`
  - `tau`: `[0.0, 0.5]`
  - `gamma`: `[6.0, 10.0]`
  - `beta_v`: `[100.0, 300.0]`
  - `epsilon_v`: `[0.0, 0.2]`
  - `fallback_p`: `[0.7, 1.0]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
import numpy as np

def predict(parameters, state, history):
    # Validity-gated tallying.
    # state is the current pair of option feature vectors, shape (2, n_features).
    # Row 0 = option A, row 1 = option B. History is irrelevant because choices
    # are made independently on each trial with no feedback.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Validity-gated tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    validities = np.asarray(parameters["validities"], dtype=float)
    n_features = stim.shape[1]
    if validities.shape[0] != n_features:
        raise ValueError(
            f"validities length {validities.shape[0]} != n_features {n_features}."
        )

    a, b = stim[0], stim[1]
    diff = a - b

    # Unweighted tally of strict feature-wise wins; tied features contribute nothing.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    tally_d = a_wins - b_wins

    tau = float(parameters["tau"])

    def stable_softmax(scores, inv_temp):
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        p = e / np.sum(e)
        return p

    if np.abs(tally_d) > tau:
        # Unequal tallies: exactly the Tallying softmax, preserving majority-tally
        # choice behavior on clearly discriminating trials.
        scores = np.array([a_wins, b_wins])
        p_core = stable_softmax(scores, float(parameters["beta_tally"]))
        eps_tally = float(parameters["epsilon_tally"])
        probs = (1.0 - eps_tally) * p_core + eps_tally * np.array([0.5, 0.5])
    else:
        # Tally tie or near-tie: validity-gated integration instead of guessing.
        gamma = float(parameters["gamma"])
        weights = np.maximum(validities - 0.5, 0.0) ** gamma
        v = float(np.dot(weights, diff))

        scores_v = np.array([v, -v])
        p_core_v = stable_softmax(scores_v, float(parameters["beta_v"]))
        eps_v = float(parameters["epsilon_v"])
        p_valid = (1.0 - eps_v) * p_core_v + eps_v * np.array([0.5, 0.5])

        fallback_p = float(parameters["fallback_p"])
        probs = fallback_p * p_valid + (1.0 - fallback_p) * np.array([0.5, 0.5])

    probs = np.clip(probs, 0.0, 1.0)
    total = probs.sum()
    if total <= 0.0:
        probs = np.array([0.5, 0.5])
    else:
        probs = probs / total
    return probs
```

**`policy(probs)`:**
```python
import numpy as np

def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = probs.sum()
    if total <= 0.0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / total
    return int(np.random.choice(len(probs), p=probs))
```
