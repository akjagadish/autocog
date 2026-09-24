# experiment_attempt_00

## System Prompt

You are a renowned cognitive scientist designing an experiment in the Decision Making (Binary Features) domain.

Your goal is to be an adversarial collaborator: propose a design whose outcomes would be predicted by your advocated theory but NOT by the competing theory. Both are provided below.

A useful proposal targets a *quantitative* dissociation between the two theories — how they respond differently to specific stimuli in addition to differences in overall performance.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

A multi-attribute decision-making experiment. On each trial the subject sees two options (A, B), each described by `n_features` integer expert ratings (`n_features` is set by the length of `validities` you propose). Choose `validities` — one per feature, each in [0.5, 1.0], order free — to fix each expert's advertised accuracy; subjects are told these values up front. Then choose `trial_a_ratings/trial_b_ratings` (each rating value in [0, 1]) so that the intended decision-making theories make distinguishable predictions: avoid degenerate pairs where every theory agrees, and prefer pairs that maximally dissociate the candidate theories. Validities and the trial ratings together define the design; they are fixed across all trials in this experiment. No trial-by-trial correctness feedback. The total number of trials per subject is held at roughly 96: each unique pair is repeated K = max(1, 96 // n_unique_pairs) times in an independently-randomized order per subject.

Subjects see the following instructions:
In this experiment you will repeatedly choose between two fictitious products, A and B. On every trial you will see `n_features` expert ratings for each product (the number of experts is fixed across all trials and is set by the length of `validities`).

Each rating is an integer in [0, 1]. The ratings are displayed as a horizontal filled bar with the numeric value (e.g. "0/1") shown next to it. Higher = more positive.

The same experts (in the same order) provide ratings for both products on every trial. Each expert's accuracy (their validity expressed as a percentage, e.g. "Expert 1 (80%)") is shown next to their rating on every trial AND is also listed up front in an "Expert accuracies" panel.

On each trial, decide which product is of higher quality and press A for product A or B for product B. There is no time limit and no feedback. Note that for the first ~`min_rt_ms` of each trial the answer prompt is hidden and the keys are locked, so subjects first see the full ratings and can answer once the A / B prompt appears — design pairs that actually require comparing the ratings.

Total trials per subject is roughly `MAX_TRIALS`: each unique pair you propose is repeated `K = max(1, MAX_TRIALS // n_unique_pairs)` times in an independently-randomized order per subject.

## ADVOCATED THEORY
**Description:** People adaptively decide whether unweighted tallying is diagnostic in the current task. They monitor two context signals over recent stimulus history: the prevalence of tally ties and the mean absolute per-trial validity-weighted evidence on those tie trials. When ties are rare, choice remains essentially unweighted tallying. When ties are prevalent and validity evidence is diagnostically substantial in absolute magnitude on tie trials, a validity-based tie-break policy is recruited. The recruitment is near-binary rather than continuous, so low-tie tasks recover near-tallying behavior while high-tie diagnostic tasks show strong validity-aligned tie-breaking. Unlike a fixed validity-gated tallying rule, the validity route is switched by task composition, and unlike continuous validity grading, validity is not mixed into every trial.

**Parameters:**
- beta_tally: [4.0, 20.0]
- epsilon_tally: [0.0, 0.5]
- tau_tie: [0.0, 0.5]
- lambda_min: [0.0, 0.005]
- lambda_max: [0.93, 0.96]
- c0: [0.56, 0.575]
- gate_width: [0.03, 0.05]
- ctx_power: [0.5, 0.8]
- history_window: [100.0, 200.0]
- beta_v: [10.0, 30.0]
- epsilon_v: [0.0, 0.05]
- gamma: [3.0, 7.0]
- consistency_floor: [0.05, 0.10]
- min_cons_ties: {2, 3}
- validities: validities

**`predict source code`:**
```python
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Context-gated tallying expects a (2, n_features) stimulus; got shape %s.' % (stim.shape,))

    validities = np.asarray(parameters['validities'], dtype=float)
    n_features = stim.shape[1]
    if validities.shape[0] != n_features:
        raise ValueError('validities length %d != n_features %d.' % (validities.shape[0], n_features))

    a = stim[0]
    b = stim[1]
    diff = a - b

    wins_a = float(np.sum(a > b))
    wins_b = float(np.sum(b > a))
    tally_d = wins_a - wins_b

    tau_tie = float(parameters['tau_tie'])

    h_a = history.get('option_a_ratings', [])
    h_b = history.get('option_b_ratings', [])
    n_past = min(len(h_a), len(h_b))

    window = int(round(float(parameters['history_window'])))
    if window < 1:
        window = 1
    start = max(0, n_past - window)

    lin_weights = validities - 0.5
    tie_count = 0.0
    abs_evidence_sum = 0.0

    for i in range(start, n_past):
        pa = np.asarray(h_a[i], dtype=float)
        pb = np.asarray(h_b[i], dtype=float)
        past_wins = float(np.sum(pa > pb)) - float(np.sum(pb > pa))
        if abs(past_wins) <= tau_tie:
            tie_count += 1.0
            v_lin = float(np.dot(lin_weights, pa - pb))
            abs_evidence_sum += abs(v_lin)

    current_tie = 1.0 if abs(tally_d) <= tau_tie else 0.0
    tie_count += current_tie
    if current_tie:
        v_lin_current = float(np.dot(lin_weights, diff))
        abs_evidence_sum += abs(v_lin_current)

    total_considered = min(n_past, window) + 1.0
    c = tie_count / total_considered if total_considered > 0.0 else 0.0

    mean_abs_evidence = abs_evidence_sum / max(tie_count, 1.0)

    c0 = float(parameters['c0'])
    gate_width = float(parameters['gate_width'])
    ctx_power = float(parameters['ctx_power'])
    lambda_min = float(parameters['lambda_min'])
    lambda_max = float(parameters['lambda_max'])
    consistency_floor = float(parameters['consistency_floor'])
    min_cons_ties = int(parameters['min_cons_ties'])

    g = float(np.clip((c - c0) / max(gate_width, 1e-12), 0.0, 1.0))

    if tie_count >= min_cons_ties and mean_abs_evidence >= consistency_floor:
        veto = 1.0
    else:
        veto = 0.0

    lamb = lambda_min + (lambda_max - lambda_min) * (g ** ctx_power) * veto

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        p = e / np.sum(e)
        return p

    beta_t = float(parameters['beta_tally'])
    eps_t = float(parameters['epsilon_tally'])
    p_tally = stable_softmax(np.array([wins_a, wins_b]), beta_t)
    p_tally = (1.0 - eps_t) * p_tally + eps_t * np.array([0.5, 0.5])

    gamma = float(parameters['gamma'])
    weights = np.maximum(validities - 0.5, 0.0) ** gamma
    v = float(np.dot(weights, diff))

    beta_v = float(parameters['beta_v'])
    eps_v = float(parameters['epsilon_v'])
    p_valid = stable_softmax(np.array([v, -v]), beta_v)
    p_valid = (1.0 - eps_v) * p_valid + eps_v * np.array([0.5, 0.5])

    probs = lamb * p_valid + (1.0 - lamb) * p_tally
    probs = np.clip(probs, 0.0, None)
    total = probs.sum()
    if total <= 0.0:
        probs = np.array([0.5, 0.5])
    else:
        probs = probs / total

    return probs
```

**`policy source code`:**
```python
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=np.float64)
    p = np.clip(p, 0.0, None)
    total = p.sum()
    if total <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / total
    return int(np.random.choice(len(p), p=p))
```


## COMPETING THEORY
**Description:** People use a validity-graded compensatory integration rule. On every choice they inspect all features, compute a signed option advantage by summing each discriminating feature's contribution, and then choose via a softmax over that advantage plus an independent lapse. Unlike Take The Best there is no early stopping. Unlike pure Tallying, each feature's contribution is weighted by a validity-sensitive multiplier. The multiplier is anchored around equal weighting, w_j = 1 + kappa * (v_j - mean(v)), normalized so the average weight is exactly 1. Because kappa has a symmetric prior centered at zero, the population-level expected weight vector is the equal-weight vector, but individual subjects may slightly overweight or underweight higher-validity cues. Tied features contribute nothing.

**Parameters:**
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- kappa: [-0.10, 0.10]
- validities: validities

**`predict source code`:**
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

**`policy source code`:**
```python
import numpy as np

def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## ALREADY-EXPLORED EXPERIMENTS (do not repeat)
[0] This design uses six binary cues with widely spread validities. It places TTB's first discriminating cue at position 0, 1, or 2 in the validity-sorted order, while packing the later cues to oppose or tie the tallying score. In half the unique pairs the first discriminating cue favors A and in half it favors B. TTB therefore predicts p(A) is uniformly high for all six TTB-A trials and uniformly low for all six TTB-B trials, because later cues are never consulted after the first discriminating cue. Tallying instead ignores validity and counts all features: in the six oppose pairs the tally winner is opposite to TTB (count differences of 1 vs 5, 1 vs 4, and 1 vs 3), producing a crossover; in the six tie pairs tallying predicts 0.5 regardless of beta. The 12 unique pairs are each repeated 8 times for roughly 96 trials per subject. This gives a quantitative dissociation: TTB choice probability should be invariant within first-cue winner type, whereas tallying choice probability should move from near 0 to 0.5 to near 1 across the tally-difference levels.

[1] Eight experts with validities spread from .50 to .92; the highest validity is placed at display index 4 so TTB must re-sort and cannot be mimicked by left-to-right scanning. In every unique pair the top cue discriminates: trials 1-8 have top cue A, trials 9-16 top cue B. TTB therefore predicts a constant p(A) within each block (sigmoid(beta) for A-top, sigmoid(-beta) for B-top, plus lapse), because lower cues are never consulted. Tallying instead counts all eight cues, so p(A) = sigmoid(beta*d) with d = #A wins - #B wins. The d sequence is +8,+6,+4,+2,0,-2,-4,-6 for A-top and -8,-6,-4,-2,0,+2,+4,+6 for B-top. This yields a full psychometric curve for Tallying within each TTB-constant block, including d=0 pairs where Tallying must guess but TTB remains confident, and crossover pairs where the top cue and the majority of cues point in opposite directions. Mirrored blocks control for A/B response bias. 16 unique pairs x 6 repeats = 96 trials.

[2] This design dissociates validity-graded compensatory integration from pure Tallying by crossing tally difference d with a validity-composition score S. Six low-validity (0.5) and six high-validity (1.0) experts give centered validities of -0.25 and +0.25. For each pair define d = #A wins - #B wins and S = 2 * sum of centered validities of features A wins. Tallying depends only on d, so it predicts a flat p(A)=0.5 for all eight d=0 pairs, one common value for the two d=+1 pairs, and one common value for the two d=-1 pairs. Validity-graded integration predicts D = d + kappa*S, so within each d block p(A) should vary with S. The d=0 pairs span S = +3, +2.5, +2, +1, -1, -2, -2.5, -3 (the +/-2.5 pairs include tied experts), producing a psychometric curve where Tallying is flat at 0.5. The d=+1 pairs have S=+3 and -3 (D=1.3 vs 0.7 at kappa=0.1), and the d=-1 pairs have S=+2.5 and -2.5 (D=-0.75 vs -1.25), so Tallying predicts identical p(A) within each d block while the advocated theory predicts a validity-composition shift. This is a quantitative dissociation: Tallying yields a three-level step function in d, whereas the advocated theory yields a continuous S effect within each d level. Because kappa may vary across subjects, the d=0 S curve also predicts overdispersion in individual choice proportions that Tallying cannot produce.

[3] This design dissociates pure Tallying from validity-graded compensatory integration by crossing the unweighted tally difference d = #A wins - #B wins with a validity-composition score S. Ten experts have graded validities [0.5, 0.5, 0.5, 0.6, 0.7, 0.8, 0.9, 1.0, 1.0, 1.0] (mean 0.75), giving centered validities [-0.25, -0.25, -0.25, -0.15, -0.05, 0.05, 0.15, 0.25, 0.25, 0.25]. Every pair is complementary (B = 1 - A), so there are no ties, d = sum(A) - sum(B), and S = 2 * sum of centered validities of features where A = 1. The eight d = 0 pairs (A has five 1s) span S = +1.9, +1.3, +0.7, +0.1, -0.1, -0.7, -1.3, -1.9. Tallying depends only on d, so it predicts p(A) = 0.5 for all eight d = 0 pairs at every beta. Validity-graded integration predicts advantage = d + kappa * S, so for any subject with kappa != 0, p(A) must vary monotonically with S across the d = 0 pairs: high-S pairs favor A and low-S pairs favor B when kappa > 0, with the reverse when kappa < 0. This yields a quantitative dissociation: a flat line at 0.5 for Tallying versus a psychometric S curve for the competing theory, plus overdispersion in individual d = 0 choice proportions that Tallying cannot produce. The four d = +/-2 pairs (two with S = +1.8, two with S = -1.8) serve as controls to estimate beta and the d effect. Twelve unique pairs x 8 repeats = 96 trials.

[4] Sixteen experts: eight with validity 0.50 and eight with validity 1.00, so centered validities are -0.25 and +0.25. This binary spread maximizes the validity-composition score S = sum_j (v_j - 0.75)*(A_j - B_j) for a fixed tally difference and makes the competing fallback weights (v_j - 0.5)^gamma exactly zero for low-validity experts. The 16 unique pairs are organized into three blocks. (1) Six d=+1 pairs (A wins one more feature than B) with S = -3.75, -2.75, -1.75, 0.25, 1.25, 3.75. (2) Six d=-1 pairs, the A/B swaps of the first block, with S = 3.75, 2.75, 1.75, -0.25, -1.25, -3.75. (3) Four d=0 tally-tie pairs in which the high-validity tally H = #high A wins - #high B wins is +8, +4, -4, -8. On the non-tie pairs the competing validity-gated tallying rule never opens its validity gate because |d| > tau, so it predicts a single p(A) for all six d=+1 pairs and a single p(A) for all six d=-1 pairs, regardless of S. The advocated validity-graded integration predicts advantage D = d + kappa*S, so within each d block p(A) must vary with S for any subject with kappa != 0 (e.g., D shifts by +/-0.375 at kappa=0.1), giving a within-block S psychometric curve and overdispersion. On the d=0 pairs the competing rule opens its validity gate and, with high beta_v, predicts p(A) strongly follows the high-validity tally (high for H=+8/+4, low for H=-4/-8, scaled by fallback_p), whereas the advocated rule predicts D = kappa*S and, because kappa has a symmetric zero-centered prior, aggregate p(A)=0.5 for all four tie pairs. Thus the design produces a double dissociation: non-tie trials test continuous validity reweighting against a closed gate, and tie trials test the gated validity fallback against a zero-average compensatory rule. Swapped pairs control for A/B response bias; 16 unique pairs x 6 repeats = 96 trials.

[5] Twelve experts with graded validities (mean .75) give centered validities [-.25,-.25,-.25,-.25,-.15,-.05,.05,.15,.25,.25,.25,.25]. The four d=0 pairs are constructed so the centered-validity score S=sum c_j(A_j-B_j) is exactly 0. For validity-graded compensatory integration, advantage D=d+kappa*S=0, so p(A)=.5 for every kappa. For validity-gated tallying, d=0 opens the validity gate; V=sum (v_j-.5)^gamma*(A_j-B_j) is dominated by the 1.0 experts. T1/T2 have V>0 (A favored) and T3/T4 have V<0 (B favored), so p(A) is pushed above/below .5 with strength scaled by fallback_p. This is a flat-line vs high-low dissociation. The four d=+/-1 non-tie pairs cross d with S=+/-2.35. Since |d|=1>tau, gated tallying predicts p(A) depends only on d (identical within d=+1 and within d=-1), while compensatory integration predicts D=d+kappa*S, so p(A) shifts with S within each d block. Mirrored pairs control A/B response bias. 8 unique pairs x 12 repeats = 96 trials.

[6] This design uses 11 graded experts with mean validity 0.75 and centered validities from -0.25 to +0.25. Eight of the twelve unique pairs are tally ties, d = sum(A - B) = 0, constructed to have large absolute linear validity evidence on tie trials (0.75 to 1.50). The competing context-gated tallying rule therefore sees tie prevalence c = 8/12 = 0.667 and mean tie evidence far above its consistency floor, so after warm-up its validity gate opens to lambda near lambda_max (0.93 to 0.96). The four remaining pairs are critical non-tie crossovers. In C1, d = +3 and S = sum centered_validities * (A - B) = -1.40. In C3, d = +1 and S = -1.50. For the advocated validity-graded integration, D = d + kappa * S with absolute kappa at most 0.10, so C1 gives D between 2.86 and 3.14 and C3 gives D between 0.85 and 1.15; p(A) is therefore above 0.5 for both, and higher for C1 than C3, regardless of kappa sign. For the competing rule with the gate open, the top-validity experts favor B in C1 and C3, so V = sum (v_j - 0.5)^gamma * (A_j - B_j) is negative; p_valid(A) is below 0.5 across the specified gamma and beta_v ranges, and mixing that with the near-1 tally route at lambda around 0.94 keeps overall p(A) below 0.5, typically well below. Thus C1 and C3 produce a sign reversal: advocated theory predicts A-favoring choices, competing theory predicts B-favoring choices once the gate is open. C2 and C4 are exact A/B swaps and give mirrored predictions. The eight d = 0 filler pairs add a second dissociation: advocated theory predicts only small kappa * S shifts around chance, while the gated competing rule predicts strong validity-driven near-1 or near-0 choices after gate opening. Finally, because the competing gate is history-dependent, it predicts a temporal change on the critical crossover pairs from early tally-like choices to later validity-like choices, whereas advocated theory predicts no history effect.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- rationale: Reasoning behind this experimental design; used when interpreting results.
- validities: Per-expert validities, one per feature. Each must be in [0.5, 1.0]; order is free (no descending requirement — theories that depend on validity order re-sort internally). Length determines n_features for the whole experiment and must match the rating-list length in every trial pair. Pick a spread (at least one high validity and at least one low one) — uniform validities (e.g. all 0.7) make many candidate theories indistinguishable, so spread them out.
- trial_a_ratings: List of option-A rating vectors, one per trial. Each inner list has length equal to len(validities); each value is binary (0 or 1). `trial_a_ratings[i]` pairs with `trial_b_ratings[i]` on trial i.
- trial_b_ratings: List of option-B rating vectors, one per trial. Same length and shape constraints as `trial_a_ratings`. Pick trials that let the intended theories be dissociated; avoid trials where every theory agrees.


## Response

```json
{
  "rationale": "This 20-feature design uses 10 experts with validity 1.00 and 10 experts with validity 0.50, so mean validity is 0.75 and centered validities are +0.25 for the first 10 features and -0.25 for the last 10 features. All unique pairs have tally difference d = +1 or -1, so there are zero tally ties. The context-gated tallying theory therefore stays in its unweighted tallying mode throughout: tie prevalence is zero, the validity gate never opens, and p(A) depends only on d. Within the d=+1 block, the validity-composition score S = sum_j (v_j - 0.75) * (a_j - b_j) takes values +4.75, +2.75, +0.75, -0.75, -2.75, and -4.75; the d=-1 block is the exact A/B swap. The advocated theory predicts one flat p(A) across all six d=+1 pairs and one flat p(A) across all six d=-1 pairs. The competing validity-graded integration predicts D = d + kappa * S, so for any subject with kappa not equal to zero p(A) must be monotone in S within each d block; across subjects with a symmetric kappa prior this appears as S-linked slope or overdispersion rather than the advocated flat S-independent curve. Mirrored swaps control response bias and create a quantitative double dissociation: two flat d-based levels versus two S-ordered psychometric gradients.",
  "validities": [
    1.0,
    1.0,
    1.0,
    1.0,
    1.0,
    1.0,
    1.0,
    1.0,
    1.0,
    1.0,
    0.5,
    0.5,
    0.5,
    0.5,
    0.5,
    0.5,
    0.5,
    0.5,
    0.5,
    0.5
  ],
  "trial_a_ratings": [
    [
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ]
  ],
  "trial_b_ratings": [
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1
    ]
  ]
}
```

## Usage

```json
{
  "input_tokens": 6827,
  "output_tokens": 43327,
  "reasoning_tokens": 41394,
  "provider": "Baidu"
}
```
