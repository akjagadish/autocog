# Round 1 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** Validity-Weighted Tallying (graded-evidence regime): people integrate evidence from ALL binary expert ratings, casting each feature a sign vote (+1 win / -1 loss / 0 tie) weighted by w_j = validity_j^gamma, summing into a zero-sum evidence score, with choice a softmax (inverse temperature beta) over the two scores plus an independent uniform lapse (epsilon). The theoretical claim added this round is about where humans sit in this family: in the UNSATURATED softmax regime. Because the evidence scores are integer-scale sign tallies, beta >= 3 already drives tanh(beta*m) ~ 1 for every unit margin, making the model behaviorally deterministic and pinning it to the tallying corner; the graded dose-response in tally margin that both experiments demand (Exp 1 metric at 44% of the deterministic-tally value; Exp 2's small positive b_d) lives at beta ~ 0.2-0.3, where p(A) is approximately linear in the tally margin. Gamma stays in a mild, provably sub-lexicographic band so that no subject leaps into the TTB regime.

**Rationale:** This is a minimal-diff edit of the running-best (iter 3, ACCEPTED, loss 0.1606) candidate: the mechanism code is byte-identical (w_j = validity_j^gamma sign votes, zero-sum scores, stable softmax, uniform lapse); ONLY the parameter ranges change. Why I deviate from the critic's specific numbers (beta capped 3-5, epsilon floored 0.03-0.05, gamma in [0.2, 1.0]): with zero-sum sign-vote scores the softmax input is the integer tally margin m, so p(A) = sigmoid(2*beta*m) and, in the sub-flip gamma regime, Exp 1's metric is exactly -(1-epsilon)*(1/6)[tanh(beta) + tanh(2*beta) + tanh(3*beta)]. At beta = 3 this already equals -0.4995 -- indistinguishable from beta = 10 -- so capping beta at 3-5 and flooring epsilon at 0.03-0.05 leaves Exp 1 pinned at ~-0.45 (the iter-3 corner), moving it at most ~0.02 toward the real -0.218; the gate would reject. The lever the critic's diagnosis points at but its numbers don't reach is the UNSATURATED softmax regime: the real Exp 1 value (-0.218 = 44% of the deterministic-tally value -0.50) requires (1/6)*sum(tanh(k*beta)) ~ 0.44, i.e. beta ~ 0.24; independently, Exp 2's b_d must equal ~0.077, and b_d(beta) ~ 0.08 exactly at beta ~ 0.2 (b_d(0.1)=0.048, b_d(0.23)=0.091, b_d(0.5)=0.128 on the Exp 2 design). Both experiments' targets sit in the SAME low-beta band -- a joint consistency check that this is where the data live, and precisely the 'graded dose-response in tally margin' the arbiter prescribed this family to capture (at beta ~ 0.25, p(A) ~ 0.5 + 0.24*d, linear in margin). Hence beta: [0.03, 0.55]. Variance: the critic correctly flagged that iter 3 undershot the between-subject variances (0.0050 / 0.0008 vs real 0.0140 / 0.0031). With per-subject parameter sampling, spreading beta over [0.03, 0.55] makes subject-level Exp 1 metrics range from ~-0.03 to ~-0.36 (between-subject sd ~ 0.10, var ~ 0.010) which, added to within-subject binomial noise (~0.005), lands at ~0.013-0.015 -- matching the real 0.0140 without iter 1's blowup (0.0635, caused by gamma wandering across cue-flip thresholds). Gamma stays in a mild band [0.05, 0.7]: for validities in [0.5, 1.0], at any gamma <= 1 two opposing cues always out-weigh one top cue (2*0.5^gamma >= 1 >= v0^gamma), so no simulated subject can flip into the TTB regime that ruined iter 1; gamma instead gently compresses the weighted margins at low beta and injects the small top-cue effect (b_s > 0 in Exp 2) that trims +0.124 toward +0.077. Epsilon stays small ([0.0, 0.08], mean attenuation ~4%) so it calibrates rather than drives. Expected landing zone: Exp 1 ~ -0.21 (var ~ 0.013) and Exp 2 ~ +0.08 (var ~ 0.002) vs real (-0.218, 0.0140) / (+0.077, 0.0031) -- an order-of-magnitude improvement over the base's deltas (+0.243 / +0.047), with every deviation the critic listed (Exp 1 overshoot, both variance undershoots) moved in the correcting direction.

**Parameters:**
  - `gamma`: `[0.05, 0.7]`
  - `beta`: `[0.03, 0.55]`
  - `epsilon`: `[0.0, 0.08]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Validity-Weighted Tallying.
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    # Each feature j casts a vote sign(a_j - b_j) for A's score and
    # the opposite for B's score; votes are weighted by w_j =
    # validity_j ** gamma. gamma = 0 -> unweighted Tallying;
    # gamma -> large -> lexicographic TTB (top cue dominates).
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    n_features = stim.shape[1]
    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    # Validity-based weights. Since validities are in [0.5, 1.0],
    # gamma = 0 gives all-ones weights (pure Tallying); increasing
    # gamma increasingly privileges high-validity cues, with the
    # top cue dominating as gamma grows (TTB limit).
    w = np.power(val, gamma)

    # Weighted evidence scores. B's score is the mirror of A's
    # because every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a])

    # Numerically stable softmax over the two weighted scores.
    # When all cues tie (s_a == 0) the softmax is exactly uniform,
    # which is the correct behavior for an undiscriminating tally.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))
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

**Description:** Flattened-Diagnosticity Evidence Integration (the extreme-compression corner of the Bayesian cue-counting family): people integrate ALL binary expert ratings into one evidence score, where each discriminating cue casts a sign vote weighted by w_j = max(log(v_j/(1-v_j)) - tau, 0)^delta — chance cues (v=0.5) are annihilated exactly, but among genuinely diagnostic cues the subjective weight is a HEAVILY flattened (delta ~ 0.15) version of the normative log-odds, and choice is a low-gain softmax (2*beta ~ 0.6) plus a small uniform lapse. The new theoretical claim is that the compression exponent delta is itself the structural margin-compression device: shrinking delta equalizes weights, which GROWS count-dominated conflict margins (where cues split across options) while SHRINKING alignment-dominated cumulative margins (where several strong cues pile onto one side). This differential action — not any global gain knob, and not trial-level normalization — is what lets a single small beta simultaneously produce moderate TTB-leaning conflict-trial behavior (Exp 1), a slightly positive tally-vs-top-cue regression slope (Exp 2), graded ~0.62 tally-following (Exp 3), and near-chance |d|=1 agreement driven by the cancellation between super-expert matches and super-expert reversals (Exp 4).

**Rationale:** MINIMAL-DIFF EDIT: the code is the accepted iter-2 base VERBATIM; the only change is the parameter box (delta, tau, beta, epsilon). I accept the critic's iter-3 DIAGNOSIS in full (Exps 3/4 are saturated by large cumulative margins; Exps 1/2 need more effective gain; no global beta/epsilon can serve both) but I reject its prescribed FIX (kappa normalization) on quantitative grounds, and I reject the delta floor of ~0.35 as well. (1) WHY KAPPA HAS THE WRONG SIGN. Normalization divides the margin by (sum of discriminating weights)^kappa. Exp 1's conflict trials have 3-4 discriminators splitting across options (net weighted margin ~0.6-0.9, total weight ~3.6-4.2), so kappa=1 compresses their effective signal to ~0.17-0.25 — exactly the trials that need MORE gain. Exp 4's single-super-expert |d|=1 types have one discriminator, so m_norm = w0/w0^kappa = w0^(1-kappa), i.e. exactly 1 at kappa=1 — unsaturable only at beta ~ 0.1, which collapses Exp 1 to ~-0.01. Kappa compresses the trials that need gain and spares the trials that need compression: the opposite of the required differential action. (2) THE CORRECT IN-FAMILY STRUCTURAL KNOB IS DELTA ITSELF. Shrinking delta from 0.5 to 0.15 equalizes weights: count-dominated conflict margins GROW (Exp 1 type-1: -0.62 -> -0.91, because the tally side's cue count reasserts itself) while alignment-dominated cumulative margins SHRINK (Exp 4's super-expert sum W = w0+w1+w2: 4.8 -> 3.4). The ratio W/conflict drops from ~5 to ~2.6, so ONE small gain (2*beta ~ 0.6) puts Exp 1 conflicts at tanh ~ 0.27-0.49, Exp 4 matches at sigma ~ 0.65-0.82, and — critically — Exp 4's reversed types (three super-experts opposing the raw tally) at 1-sigma(2*beta*W) ~ 0.10-0.16, whose cancellation against the matches is what holds the |d|=1 metric near 0.51 instead of the saturated 0.58-0.60 of iter 2. (3) VALIDATION OF THE ALGEBRA. Applying the same margin-level computation at the ACCEPTED iter-2 box center (delta 0.4, beta 0.65) reproduces that candidate's actual outputs almost exactly: predicted Exp 1 = -0.288 vs actual -0.2795; predicted Exp 4 = 0.583 vs actual 0.5796. The algebra is therefore trustworthy, and it identifies (delta ~ 0.15, beta ~ 0.3) as the simultaneous optimum: Exp 1 ~ -0.21 to -0.22 (target -0.218), Exp 2 ~ +0.06 (target +0.077; near-equal weights keep b_d positive while the small cue-0 tilt keeps b_s small), Exp 3 ~ 0.61-0.63 (target 0.617), Exp 4 ~ 0.52 (target 0.513). (4) WHY THIS IS NOT OSCILLATION. The delta box [0.10, 0.20] extends the ACCEPTED base's [0.20, 0.6] downward — it is not a return to the critic's rejected delta~1 regime — and the annihilation property (llr(0.5)=0 <= tau for every tau in the box) is preserved everywhere, so the validated Exp 4 mechanism survives intact. The beta box [0.27, 0.37] is the critic's requested restoration of gain, rescaled to the ~2.5x smaller margins that delta-compression produces (equivalent effective gain to the critic's [0.35, 1.0] at delta 0.5). Expected residuals: |Exp1| ~ 0.01, |Exp2| ~ 0.02, |Exp3| ~ 0.01-0.03, |Exp4| ~ 0.01 — every one at or below the accepted base's residuals (0.062, 0.026, 0.050, 0.066), with the two dominant errors (Exp 1 and Exp 4) essentially eliminated.

**Parameters:**
  - `delta`: `[0.1, 0.2]`
  - `tau`: `[0.0, 0.04]`
  - `beta`: `[0.27, 0.37]`
  - `epsilon`: `[0.0, 0.05]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Diagnosticity-Weighted Evidence Integration (Bayesian cue-counting).
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings (0/1).
    # Each feature j casts a sign vote sign(a_j - b_j); the vote is
    # weighted by the cue's log-likelihood-ratio diagnosticity
    # llr_j = log(v_j / (1 - v_j)), rectified by an attention floor
    # tau and compressed by an exponent delta:
    #   w_j = (max(llr_j - tau, 0))^delta
    # A v = 0.5 expert has llr = 0 -> exactly zero evidence.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    n_features = stim.shape[1]
    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    delta = float(parameters["delta"])
    tau = float(parameters["tau"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    # Normative diagnosticity: log-likelihood-ratio of each expert.
    # Clip away from v = 1.0 to keep the log finite; v = 0.5 maps to 0.
    v = np.clip(val, 0.5, 1.0 - 1e-9)
    llr = np.log(v / (1.0 - v))

    # Limited-attention floor: diagnosticity below tau is discarded;
    # the remainder is compressed by the exponent delta. delta = 1 is
    # the purely normative Bayesian weight; delta < 1 flattens the
    # diagnosticity gradient toward tallying over informative cues
    # (while v = 0.5 cues stay annihilated at any delta, since
    # llr(0.5) = 0 <= tau); delta > 1 sharpens it toward
    # lexicographic/TTB-like use of the best experts.
    w = np.power(np.maximum(llr - tau, 0.0), delta)

    # Weighted evidence score. B's score is the mirror of A's because
    # every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a])

    # Numerically stable low-temperature softmax. When all attended
    # cues tie (s_a == 0) the softmax is exactly uniform, which is the
    # correct behavior for undiscriminating evidence.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy(probs)`:**
```python
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))
```
