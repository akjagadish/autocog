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
Broad-Spectrum Skepticism Tallying (BSST), low-gain/held-cliff calibration. People integrate ALL binary expert ratings as sign votes (+1/-1/0) into a zero-sum evidence score, where the subjective weight w(v) is a wide inverted-U over STATED validity with skepticism on both flanks: (i) chance experts (v = 0.5) carry a small negative weight (~0.23 trusted-cue units) — a coin-flipper's endorsement is mildly anti-diagnostic; (ii) the entire band v ~ [0.55, 0.95] is a flat trust plateau (~0.9), making mid-band experts nearly exchangeable and generating moderate unweighted-tally behavior; (iii) distrust of claimed certainty is CONCENTRATED in a very sharp cliff between 0.98 and 0.99: w(0.98) stays mildly positive while w(0.99) plunges to ~ -1.1 trusted-cue units. The calibration claim added this round is about the GAIN-FLANK DECOUPLING: the softmax gain beta can be lowered (0.34) while the chance-flank magnitude kappa_lo is raised (0.23) so that the product beta*kappa_lo (~0.077) — the quantity that pins the chance-cue signature — is held invariant, but the product beta*|w(0.99)| (~0.37) is allowed to FALL because kappa_hi is held at its iter-2 value rather than deepened. This is the one combination never tried in nine iterations: every prior beta reduction (iters 5, 9) was bundled with a kappa_hi increase that exactly cancelled the gain on the 0.99-driven cells.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # Broad-Spectrum Skepticism Tallying (BSST), sharp-late-cliff edition.
    # Stimulus: array of shape (2, n_features); row 0 = option A,
    # row 1 = option B; entries are binary expert ratings.
    # Each feature j casts a sign vote sign(a_j - b_j); the vote is
    # weighted by a wide inverted-U 'skepticism' function of the
    # expert's STATED validity v:
    #   v <= v_rise :  w = -kappa_lo * (v_rise - v)/(v_rise - 0.5)
    #                  (chance experts: linear lobe, w(0.5) = -kappa_lo;
    #                   a coin-flipper's endorsement is mildly
    #                   anti-diagnostic noise)
    #   v >  v_rise :  w = w_plateau - (w_plateau + kappa_hi)
    #                        * sigmoid((v - v_c)/s_hi)
    #                  (flat trust plateau over the mid-band -- the
    #                   logistic is ~0 for every v <= 0.95, so all
    #                   mid-band experts get the full plateau weight;
    #                   then an extremely SHARP distrust cliff packed
    #                   between 0.98 and 0.99: w(0.98) stays mildly
    #                   positive, w(0.99) plunges to ~ -1.1 trusted-cue
    #                   units, saturating at -kappa_hi as v -> 1)
    # Votes are summed into a zero-sum evidence score; choice is a
    # low-gain softmax with inverse temperature beta plus a uniform
    # lapse epsilon.
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

    v_rise = float(parameters["v_rise"])
    w_plateau = float(parameters["w_plateau"])
    v_c = float(parameters["v_c"])
    s_hi = float(parameters["s_hi"])
    kappa_lo = float(parameters["kappa_lo"])
    kappa_hi = float(parameters["kappa_hi"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    a, b = stim[0], stim[1]

    # Feature-wise votes: +1 where A wins the feature, -1 where B
    # wins, 0 on ties (a tied cue is uninformative for the pair).
    votes = np.sign(a - b)

    v = np.clip(val, 0.5, 1.0)
    w = np.empty(n_features, dtype=float)

    # (i) Low flank: chance experts carry a small negative weight,
    # linearly reaching -kappa_lo at v = 0.5 and 0 at v_rise.
    lo = v < v_rise
    denom_lo = max(v_rise - 0.5, 1e-6)
    w[lo] = -kappa_lo * np.clip(v_rise - v[lo], 0.0, None) / denom_lo

    # (ii)+(iii) Flat trust plateau followed by an extremely sharp
    # distrust cliff concentrated between v = 0.98 and v = 0.99.
    # In the mid-band the logistic term is ~0, so w ~ w_plateau
    # (nearly equal weights -> tally-like counting); at 0.98 the
    # weight is only mildly discounted, at 0.99 it is strongly
    # anti-diagnostic, and it saturates at -kappa_hi as v -> 1.
    hi = ~lo
    # Numerically stable logistic.
    x = (v[hi] - v_c) / s_hi
    sig = np.where(x >= 0, 1.0 / (1.0 + np.exp(-x)),
                   np.exp(x) / (1.0 + np.exp(x)))
    w[hi] = w_plateau - (w_plateau + kappa_hi) * sig

    # Weighted evidence score. B's score is the mirror of A's
    # because every vote is zero-sum across the two options.
    s_a = float(np.dot(w, votes))
    scores = np.array([s_a, -s_a])

    # Numerically stable low-gain softmax. When all cues tie
    # (s_a == 0) the softmax is exactly uniform.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Independent lapse: with probability epsilon output a uniform
    # pick over the two options.
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))

## THEORY 2 — pi_4
Flattened-Diagnosticity Evidence Integration (the extreme-compression corner of the Bayesian cue-counting family): people integrate ALL binary expert ratings into one evidence score, where each discriminating cue casts a sign vote weighted by w_j = max(log(v_j/(1-v_j)) - tau, 0)^delta — chance cues (v=0.5) are annihilated exactly, but among genuinely diagnostic cues the subjective weight is a HEAVILY flattened (delta ~ 0.15) version of the normative log-odds, and choice is a low-gain softmax (2*beta ~ 0.6) plus a small uniform lapse. The new theoretical claim is that the compression exponent delta is itself the structural margin-compression device: shrinking delta equalizes weights, which GROWS count-dominated conflict margins (where cues split across options) while SHRINKING alignment-dominated cumulative margins (where several strong cues pile onto one side). This differential action — not any global gain knob, and not trial-level normalization — is what lets a single small beta simultaneously produce moderate TTB-leaning conflict-trial behavior (Exp 1), a slightly positive tally-vs-top-cue regression slope (Exp 2), graded ~0.62 tally-following (Exp 3), and near-chance |d|=1 agreement driven by the cancellation between super-expert matches and super-expert reversals (Exp 4).

`predict(parameters, state, history) -> np.ndarray`:
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

`policy(probs) -> int`:
def policy(probabilities):
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return int(np.random.choice(len(probabilities), p=probabilities))

## EXPERIMENT 1 (proposed by pi_6)

### DESIGN
**Validities (n_features=11):** [0.99, 0.99, 0.98, 0.98, 0.9, 0.9, 0.5, 0.5, 0.5, 0.5, 0.5]

**Trial pairs (n=24):**
  trial 1: A=[1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 1, 0, 0, 1, 1, 0]
  trial 2: A=[0, 0, 1, 1, 1, 1, 0, 0, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 0]
  trial 3: A=[1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 1]  B=[0, 0, 0, 1, 1, 1, 1, 0, 1, 0, 1]
  trial 4: A=[0, 0, 0, 1, 1, 1, 1, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 1]
  trial 5: A=[0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1]
  trial 6: A=[1, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1]
  trial 7: A=[0, 0, 1, 1, 1, 0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0, 1, 0, 1, 1, 0]
  trial 8: A=[1, 1, 0, 0, 1, 0, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 0, 1, 0, 1, 1, 0]
  trial 9: A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 0, 1, 0]
  trial 10: A=[0, 1, 0, 1, 0, 1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 1, 0, 1, 0, 1, 0, 0, 1]
  trial 11: A=[1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0]
  trial 12: A=[1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 1, 1, 0, 0, 1, 1, 1]
  trial 13: A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 1, 1, 0, 1, 0, 1]
  trial 14: A=[0, 1, 0, 1, 1, 1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 0, 1, 1, 0, 0, 0, 1]
  trial 15: A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 1, 1, 0, 0, 0, 0]
  trial 16: A=[1, 0, 1, 0, 0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1, 1]
  trial 17: A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0, 1, 1, 1, 0, 1]
  trial 18: A=[1, 0, 1, 0, 0, 0, 1, 1, 1, 0, 1]  B=[1, 0, 1, 0, 1, 1, 0, 0, 1, 0, 1]
  trial 19: A=[1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 1, 1, 1]
  trial 20: A=[0, 1, 0, 1, 0, 1, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]
  trial 21: A=[0, 1, 1, 1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1, 1, 1, 1]
  trial 22: A=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1]
  trial 23: A=[1, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1]
  trial 24: A=[1, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]

**Rationale:** CORE LOGIC. Both theories share the identical architecture (sign votes x validity weights x softmax x lapse) and differ ONLY in the weight function. The weight functions are disjoint at three validity regimes, and each regime admits a PARAMETER-FREE knife against exactly one theory: (1) CHANCE FLANK (v=0.50): FDEI annihilates chance experts exactly (llr=0 for every delta, tau), so any trial whose discriminators are only 50% experts forces FDEI to predict EXACTLY p=0.50; BSST gives them weight -kappa_lo in [-0.235,-0.22], predicting a small graded ANTI-diagnostic ladder (this is the held-cliff calibration signature: beta*kappa_lo ~ 0.077 logits per chance cue, deliberately modest). (2) MID-BAND PLATEAU (v in [0.55,0.95]): BSST's cliff logistic is ~1e-13 at 0.90 and 0.55, so w(0.90)=w(0.55)=w_plateau EXACTLY -- any trial with tied plateau-cue counts forces BSST to predict EXACTLY p=0.50; FDEI's compressed-but-graded weights (w(0.90) in [1.08,1.17] vs w(0.55) in [0.69,0.85]) predict a systematic tilt toward the higher-validity side. (3) CLIFF FLANK (0.98 vs 0.99): BSST has w(0.98) in [0.47,0.81] (mildly trusted) but w(0.99) in [-1.35,-0.85] (strongly ANTI-diagnostic); FDEI has w(0.98) in [1.14,1.31] and w(0.99) in [1.16,1.35] -- its delta-flattening makes 98% and 99% experts nearly EXCHANGEABLE (w99-w98 in [0.02,0.04], i.e., FDEI is locked within 1 point of 0.50 on any pure 0.98-vs-0.99 contrast). Validities (11 experts): [0.99, 0.99, 0.98, 0.98, 0.90, 0.90, 0.55, 0.55, 0.50, 0.50, 0.50]. 24 unique pairs x K=4 = 96 trials.

FAMILY S (flagship cliff sign-flip). S1 (A wins both 0.99 experts, B wins both 0.90 experts): BSST box p(A) in [0.18, 0.27] (center 0.22 -- the two 99% endorsements are worth -2.2 anti-cue units against +1.81 trusted units); FDEI box [0.50, 0.55] (center 0.52 -- flattened weights make 99% barely beat 90%). DISJOINT with a ~30-point gap and a sign disagreement about whether following super-experts is above or below chance. S2 (A wins 0.99+0.99+0.98 vs B wins 0.90+0.90+0.55): BSST [0.16, 0.27] vs FDEI [0.54, 0.60] -- FDEI says A, BSST says strongly B. Mirrors S1m/S2m control side bias.

FAMILY D (the 0.98-vs-0.99 cliff that FDEI cannot see). D1 (A wins the 0.98 expert, B wins one 0.99 expert): BSST box [0.59, 0.68] (center 0.64 -- one cliff step flips the preference); FDEI locked at [0.494, 0.497] -- essentially exactly 0.50 for EVERY parameter, because w99-w98 is at most 0.04. D2 (A wins both 0.98s, B wins both 0.99s): BSST [0.68, 0.81] (center 0.75) vs FDEI [0.49, 0.50]. A 25-point dissociation on a stimulus difference (0.98 vs 0.99) that FDEI's delta-compression renders invisible. Mirrors included.

FAMILY V (cliff specificity control -- the sharpest single contrast). V1 (A wins one 0.99 expert; B wins all three 0.50 experts): BSST box [0.435, 0.499] (center 0.467: the 99% anti-vote plus three chance endorsements won by B both push toward A losing... net s = w99 + 3*kappa_lo = -0.42); FDEI box [0.57, 0.62] (center 0.594: the most diagnostic cue vs invisible chance cues). SIGN-DISJOINT. V0 (identical but A wins the 0.98 expert instead): BSST [0.58, 0.63] (center 0.605), FDEI [0.57, 0.61] (center 0.588) -- AGREEMENT by design. The V0-vs-V1 difference isolates the cliff: FDEI must predict V1 > V0 by ~0-1 points (w99 >= w98), BSST predicts V1 - V0 = -14 points crossing 0.50. A subject-level V0-V1 difference near zero falsifies BSST's cliff; near -14 falsifies FDEI's flattening. Mirrors included.

FAMILY Z (chance-flank ladder; FDEI parameter-free knife). Z1/Z2/Z3 (A wins 1/2/3 chance experts, nothing else discriminates): FDEI must predict EXACTLY 0.50 on all three for every (delta, tau, beta, epsilon). BSST predicts a monotone anti-diagnostic ladder: 0.481 / 0.463 / 0.446 (box half-widths < 0.015 -- the tightest cells in the design, since beta is pinned in [0.33,0.35] and kappa_lo in [0.22,0.235]). Any reliable negative slope of p(A) on chance-cue count, or any reliable deviation below 0.50 on Z3, falsifies FDEI with zero free parameters; a flat 0.50 falsifies the BSST chance-flank magnitude. Z3m mirrors. Note the effect is deliberately small (~2 points/cue): the held-cliff calibration pins beta*kappa_lo ~ 0.077, so the Z family is a trend/dose-response test, while the S/D/V families carry the large-effect dissociations -- recovering BOTH signatures at their predicted relative sizes is the quantitative calibration test unique to this round.

FAMILY X (chance x diagnostic interaction; mutual knife). X0 (A wins one 0.90 expert, B wins one 0.55 expert): BSST must predict EXACTLY 0.50 (plateau weights identical to machine precision); FDEI predicts [0.52, 0.54] (center 0.527). X2/X3 add 1/3 net chance cues won by A on top of the identical diagnostic background: FDEI must predict X0 = X2 = X3 EXACTLY (chance weight is identically zero -- a parameter-free flatness knife); BSST predicts a monotone ladder 0.50 -> 0.481 -> 0.446, i.e., X3 falls BELOW 0.50 while FDEI is locked ABOVE 0.52 -- a sign-disjoint cell. The X family is a double bind: X0 alone can falsify BSST (any A-tilt), the X0=X2=X3 equality alone can falsify FDEI (any slope). Xm3 mirrors. BSST additionally predicts the cross-family equalities X2=Z1 and X3=Z3 exactly (the plateau background contributes exactly 0), an internal consistency check FDEI violates (it predicts Z*=0.50 but X*=0.527).

FAMILY P (mid-band composition; BSST parameter-free knife). P1 (A wins both 0.90 experts, B wins both 0.55 experts): tied plateau counts force BSST to EXACTLY 0.50; FDEI predicts [0.53, 0.58] (center 0.553) because its graded weights give the 0.90 side a net +0.71 evidence margin. P1m mirrors (FDEI [0.42, 0.47]). Any systematic tilt on P1/P1m falsifies BSST with no parameters; exactly 0.50 falsifies FDEI's delta-flattening claim (delta would have to be ~0).

CONTROLS. T1 (the two 0.99 experts split): BOTH theories must predict exactly 0.50 -- a parameter-free side/display-bias assay. G1/G1m (all four trusted experts vs the three chance experts) are agreement anchors (BSST ~0.77/0.23, FDEI ~0.80/0.20) pinning beta and epsilon. Tie patterns mix 0/0 and 1/1 so 'count the 1s' is not viable, and every trial has 2-7 discriminators requiring genuine scanning. Sides balanced (9 A-tilted / 11 B-tilted / 4 exactly neutral under BSST centers; near-mirror under FDEI); no all-tie trials.

DIFFERENTIATION FROM PRIOR EXPERIMENTS. Unlike [1]-[3] (count-vs-weight decorrelations) and [4] (chance annihilation vs full weighting), this design's two theories are BOTH weighted and BOTH bounded, and the dissociation is carried by the SHAPE discontinuities: the 0.98/0.99 cliff (D, V families) was never contrasted directly before ([6] used 0.99 inversions but no 0.98-vs-0.99 within-pair contrast and no V0/V1 specificity pair), and the mutual parameter-free knife architecture (BSST exact-0.50 at X0/P1 vs FDEI exact-0.50 at Z/X-flatness) is new. PREDICTED PATTERN IF BSST IS RIGHT (center params): S1 .22, S2 .21, D1 .64, D2 .75, V1 .47, V0 .61, Z1/Z2/Z3 .48/.46/.45, X0 .50, X2 .48, X3 .45, P1 .50, T1 .50, G1 .77. IF FDEI IS RIGHT: S1 .52, S2 .55, D1 .50, D2 .50, V1 .59, V0 .59, Z1=Z2=Z3 .50 exactly, X0=X2=X3 .527 exactly, P1 .55, T1 .50, G1 .80. The boxes are disjoint on 18 of 24 cells; every family contains at least one parameter-free equality or exact-0.50 prediction for one theory that the other breaks in a signed, pre-registered direction.

**Computed schedule:** 24 unique pairs × 4 reps = 96 trials per subject.



### METRIC
Rationale:
I advocate BSST, whose signature is the sharp distrust cliff between v=0.98 and v=0.99 (w(0.99) ~ -1.1 trusted-cue units) plus a small negative weight on chance experts. The competing FDEI theory compresses diagnosticities so heavily (delta ~ 0.15) that a 0.98 and a 0.99 expert are nearly exchangeable (w99 - w98 in [-0.21, +0.15]) and chance cues are annihilated exactly. I therefore built the metric around the 10 pre-registered 'cliff conflict' trials (S1/S1m, S2/S2m, D1/D1m, D2/D2m, V1/V1m; 4 reps each = 40 trials per subject) in which exactly one option is endorsed by the 99% experts and the rival is endorsed only by <= 0.98-validity experts (the G1/G1m agreement anchors, where the 99-side also wins the 0.90 experts, are explicitly excluded by exact pattern matching). The metric is the rate of choosing AGAINST the 99%-endorsed option on these trials. Code-level recomputation of both predict functions over their full parameter boxes gives: BSST anti-99 rates of ~.86-.90 (S1), ~.90-.95 (S2), ~.72-.79 (D1), ~.85-.94 (D2), ~.70-.76 (V1) -> overall ~0.84; FDEI gives ~.42-.51 (S1), ~.30-.47 (S2), ~.47-.53 (D1), ~.44-.55 (D2), ~.27-.38 (V1) -> overall ~0.44. The contrast is sign-disjoint with a ~0.40 mean gap. Crucially the per-subject variance is small: each subject contributes 40 binary trials, so binomial sampling noise gives sd ~ 0.06 (BSST) / 0.08 (FDEI), and parameter heterogeneity within the boxes moves any single cell by at most a few points without ever flipping the favored side. Expected Welch t at N=25 is on the order of 15-20, far beyond the alpha=0.01 threshold, unlike small-effect contrasts (Z/X/P families, gaps ~0.03-0.10) which would be drowned in binomial noise at this sample size. The metric is a plain choice rate, so it is well defined both on the pooled DataFrame and on each single subject's 96-trial slice.

Source:
def metric(data: pd.DataFrame) -> float:
    """
    Anti-super-expert choice rate on the 10 pre-registered 'cliff conflict'
    trials (S1/S1m, S2/S2m, D1/D1m, D2/D2m, V1/V1m).

    On each of these trials exactly one option is endorsed by the
    99%-validity experts (features 0 and 1) while the rival option is
    endorsed only by experts of validity <= 0.98, and the 99%-endorsed
    side has no 0.90-class support (this excludes the G1/G1m agreement
    anchors).  The metric is the fraction of these trials on which the
    subject chooses the option NOT endorsed by the 99% experts.

    BSST (sharp distrust cliff between 0.98 and 0.99, w(0.99) ~ -1.1
    trusted-cue units, w(0.98) ~ +0.6, w(0.90) ~ +0.9, w(0.50) ~ -0.23):
    the 99%-endorsed side is disfavored on every one of these cells, with
    predicted anti-99% choice rates of roughly S1 .86-.90, S2 .90-.95,
    D1 .72-.79, D2 .85-.94, V1 .70-.76  ->  overall ~0.84.

    FDEI (delta ~ 0.15 compression makes 0.98 and 0.99 experts nearly
    exchangeable, w99 - w98 in [-0.21, +0.15]): it is locked near 0.50 on
    the D cells, mildly PRO-99% on the S cells (the 99-side also carries
    a tiny validity edge), and strongly pro-99% on V1 (three chance cues
    are annihilated exactly)  ->  overall anti-99% rate ~0.30-0.53,
    center ~0.44.  Sign-disjoint from BSST with a ~0.40 mean gap.
    """

    def as_tuple(cell):
        try:
            return tuple([int(x) for x in cell])
        except Exception:
            return None

    # key: (A ratings, B ratings) -> favored option (0 = A, 1 = B),
    # where 'favored' is the side NOT endorsed by the 99% experts.
    TRIALS = {
        # S1 / S1m  (A or B wins both 0.99; rival wins both 0.90)
        ((1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 0), (0, 0, 1, 1, 1, 1, 0, 0, 1, 1, 0)): 1,
        ((0, 0, 1, 1, 1, 1, 0, 0, 1, 1, 0), (1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 0)): 0,
        # S2 / S2m  (one side wins 0.99+0.99+0.98; rival 0.90+0.90+0.55)
        ((1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 1), (0, 0, 0, 1, 1, 1, 1, 0, 1, 0, 1)): 1,
        ((0, 0, 0, 1, 1, 1, 1, 0, 1, 0, 1), (1, 1, 1, 1, 0, 0, 0, 0, 1, 0, 1)): 0,
        # D1 / D1m  (one side wins a 0.99; rival wins a 0.98)
        ((0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1), (1, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1)): 0,
        ((1, 1, 0, 0, 1, 0, 1, 0, 1, 0, 1), (0, 1, 1, 0, 1, 0, 1, 0, 1, 0, 1)): 1,
        # D2 / D2m  (one side wins both 0.99; rival wins both 0.98)
        ((0, 0, 1, 1, 1, 0, 1, 0, 1, 1, 0), (1, 1, 0, 0, 1, 0, 1, 0, 1, 1, 0)): 0,
        ((1, 1, 0, 0, 1, 0, 1, 0, 1, 1, 0), (0, 0, 1, 1, 1, 0, 1, 0, 1, 1, 0)): 1,
        # V1 / V1m  (one side wins a 0.99; rival wins all three 0.50)
        ((1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0), (0, 1, 0, 1, 0, 1, 0, 1, 1, 1, 1)): 1,
        ((0, 1, 0, 1, 0, 1, 0, 1, 1, 1, 1), (1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0)): 0,
    }

    hits = []
    a_col = data['option_a_ratings']
    b_col = data['option_b_ratings']
    r_col = data['response']

    for a, b, r in zip(a_col, b_col, r_col):
        ka = as_tuple(a)
        kb = as_tuple(b)
        if ka is None or kb is None:
            continue
        fav = TRIALS.get((ka, kb))
        if fav is None:
            continue
        try:
            ri = int(r)
        except Exception:
            continue
        hits.append(1.0 if ri == fav else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))

### RESULTS
- Predicted under pi_6 (simulated): 0.8115 (var=0.0019)
- Predicted under pi_4 (simulated): 0.3985 (var=0.0055)
- Observed on real data: 0.5600 (var=0.0052)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=10):** [0.99, 0.98, 0.95, 0.9, 0.85, 0.75, 0.65, 0.5, 0.5, 0.5]

**Trial pairs (n=24):**
  trial 1: A=[0, 0, 1, 1, 0, 1, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]
  trial 2: A=[0, 1, 0, 1, 0, 1, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]
  trial 3: A=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 1, 0, 0, 1, 1]
  trial 4: A=[0, 0, 1, 1, 0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]
  trial 5: A=[0, 1, 0, 1, 0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]
  trial 6: A=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 1, 0, 0, 0, 1]
  trial 7: A=[1, 0, 0, 1, 0, 1, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]
  trial 8: A=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]  B=[1, 0, 0, 1, 0, 1, 0, 0, 1, 1]
  trial 9: A=[1, 0, 0, 1, 0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 1, 0, 1, 1, 1]
  trial 10: A=[0, 0, 1, 1, 0, 0, 1, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0, 1, 1, 1]
  trial 11: A=[0, 0, 0, 1, 0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 1, 0, 0, 1, 0, 0, 1]
  trial 12: A=[0, 0, 1, 1, 0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0, 1, 1, 1]
  trial 13: A=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0, 1, 1, 1]
  trial 14: A=[0, 0, 0, 1, 0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 1, 1, 0, 0, 0, 0, 1]
  trial 15: A=[0, 0, 1, 1, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0, 1, 1]
  trial 16: A=[1, 1, 0, 1, 0, 1, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1, 0, 1, 0, 1, 0]
  trial 17: A=[1, 1, 0, 1, 0, 1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1, 0, 1, 0, 1, 0]
  trial 18: A=[0, 1, 0, 0, 1, 0, 1, 0, 1, 0]  B=[1, 1, 0, 1, 0, 1, 0, 1, 1, 0]
  trial 19: A=[1, 0, 1, 1, 0, 1, 0, 1, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 1]
  trial 20: A=[1, 0, 1, 1, 0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 0, 1, 0, 1, 0, 0, 1]
  trial 21: A=[0, 0, 1, 0, 1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0, 0, 1, 1, 1]
  trial 22: A=[0, 0, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  trial 23: A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 1, 1, 1, 1, 0, 0, 0]
  trial 24: A=[1, 0, 1, 0, 1, 0, 1, 1, 0, 0]  B=[1, 0, 1, 0, 1, 0, 1, 0, 1, 0]

**Rationale:** CORE LOGIC. Both theories share the identical architecture (sign votes x validity weights x low-gain softmax x lapse) and differ ONLY in the weight function, and every validity in this design is >= 0.55, so BSST's low flank is inert and the entire dissociation is carried by two structural features never tested together: (a) BSST's FLAT PLATEAU over v in [0.55, 0.95] (all these weights equal w_plateau to within 5e-5) vs FDEI's compressed-but-strictly-MONOTONE gradient (w(0.55)=0.77 < w(0.95)=1.18 at center; the gradient is what delta > 0 exists to produce); (b) BSST's sharp 0.98/0.99 distrust cliff (w(0.98) in [0.47, 0.81], w(0.99) in [-1.35, -0.85]) vs FDEI's delta-flattened near-equality of 0.98 and 0.99 (w99 - w98 in [0.020, 0.044] across its ENTIRE box, so FDEI is locked within 0.8 probability points of invariance to a 0.98-vs-0.99 swap on any trial). Validities (10 experts): [0.99, 0.98, 0.95, 0.90, 0.85, 0.75, 0.65, 0.55, 0.55, 0.55]. 24 unique pairs x K=4 = 96 trials. Differentiation from prior experiments: no v=0.5 chance-flank logic ([4], [8]); no tally-margin decorrelation ([1]-[3]); no exchange-rate ladders against a trusted 0.90 reference ([7]); unlike [8], the cliff is tested MASKED inside balanced mid-band coalitions (where FDEI's near-invariance is parameter-free) rather than in isolated 0.98-vs-0.99 pairs, and the reciprocal PLATEAU-swap equality (invisible to BSST, visible to FDEI) is entirely new -- giving a double dissociation of SENSITIVITY ORDERING.

FAMILY V (plateau validity psychometric -- delta estimation). V1/V2/V3: A wins {0.95, v} with v = 0.65/0.75/0.85, B wins two 0.55s; V4: A wins {0.95, 0.55}, B wins two 0.55s. BSST must predict EXACTLY p(A)=0.50 on all four (every discriminator sits on the plateau, counts are 2-vs-2 tied, uniform softmax + uniform lapse) -- a parameter-free flatness knife. FDEI predicts a strictly monotone ladder in v (its w is strictly increasing for any delta > 0): centers .564 (V4), .588 (V1), .601 (V2), .612 (V3); box ranges e.g. V1 [.553,.626], V3 [.567,.662], every rung strictly above .50 across the whole box. The ladder slope is a direct delta estimate: log-odds = 2*beta*(llr(v)-tau)^delta regressed on log(llr-tau). Flat 0.50 across the ladder falsifies FDEI's delta in [0.1,0.2] outright; any single rung above ~.55 falsifies BSST with zero free parameters. Mirrors V1m/V3m control side bias.

FAMILY R (reference-validity crossover ladder -- sign dissociation and reference-ordering reversal). A wins one reference cue r in {0.95, 0.98, 0.99}, B wins k in {1,2} cues of 0.55. R1 (r=.95, k=1): BSST exactly 0.50 (plateau tie); FDEI .564 [.538,.594]. R2 (r=.98, k=1): FDEI .573 [.542,.607] vs BSST .457 [.420,.488] -- SIGN-DISJOINT around 0.50: FDEI says one 98% expert beats one 55% expert, BSST says it loses. R5 (r=.99, k=1): FDEI .577 [.545,.615] vs BSST .204 [.192,.265 with lapse] -- a 30+ point sign flip. R3/R4 (k=2): FDEI [.399,.472]/[.405,.482] vs BSST [.342,.359]/[.274,.348] -- disjoint. R6 (r=.99, k=2): FDEI [.408,.488] vs BSST [.096,.152] -- disjoint. Crossover structure: FDEI crosses 0.5 between k=1 and k=2 for EVERY reference; BSST never exceeds 0.50 for ANY reference at ANY k (its 0.98/0.99 weights are below the plateau). REFERENCE-ORDERING REVERSAL (quantitative knife both ways): R2 vs R1 and R4 vs R3 compare 0.98 vs 0.95 references at fixed k. FDEI predicts R2 > R1 and R4 > R3 STRICTLY for every parameter (llr(0.98) > llr(0.95) always), but by at most ~1 point (w98-w95 <= 0.079). BSST predicts R2 < R1 and R4 < R3 STRICTLY for every parameter (w98 <= 0.81 < plateau) -- by 2-8 points at k=1 and 4-9 points at k=2. The SIGN of the 0.95-vs-0.98 comparison separates the entire boxes of both theories. Mirrors R2m/R4m/R5m balance sides.

FAMILY M/P (masked cliff -- the sensitivity-ordering double dissociation, flagship). All cells share the balanced mid-band background A/B = {0.75, 0.55} vs {0.90, 0.85, 0.65} and embed one super cue in A's coalition. M98 (A adds 0.98): FDEI .482 (box [.475,.487] -- tightly pinned); BSST .457. M99 (A adds 0.99): FDEI .486, box [.482,.489]; BSST .204 [.192,.265]. CLIFF SWAP (M98 -> M99, a 1-point validity change): FDEI predicts |delta p| <= 0.8 points for EVERY (delta, tau, beta, epsilon) in its box (w99-w98 <= 0.044, 2*beta*that <= 0.033 logits) -- a parameter-free near-equality; BSST predicts a drop of 16-31 points. PLATEAU SWAPS: P95 (A adds 0.99+0.95+0.55... i.e., coalition {0.99, 0.95, 0.55}) and P55 (coalition {0.99, 0.55, 0.55}) differ by swapping a 0.95 for a 0.55 -- a 40-point validity change. BSST must predict P95 = P55 = M99 EXACTLY (all reduce to margin w99 - w_plateau; plateau swaps are invisible) -- parameter-free triple equality. FDEI predicts P95 (.512, box [.504,.524]) > M99 (.486) > P55 (.448, box [.429,.466]), a 4-9 point swing per swap, with P95 and P55 on OPPOSITE sides of 0.50... P55 box entirely below .466 vs BSST entirely below .265 (disjoint), P95 box entirely above .504 vs BSST entirely below .265 (disjoint, sign flip). The headline quantitative signature is the 2x2 of swap sensitivity: cliff swap (0.98->0.99): FDEI ~0 pts, BSST -16 to -31 pts; plateau swap (0.95->0.55): FDEI -4 to -9 pts, BSST exactly 0 pts. Each theory is parameter-free-insensitive to exactly the manipulation the other finds huge. Mirrors M99m/P55m balance sides.

HONEST KNIVES AGAINST MY OWN THEORY (FDEI). (i) R2: FDEI's box ceiling is .607 -- if subjects follow a lone 98% expert over a 55% expert at p >= 0.61, my flattening claim (delta <= 0.2 caps the 98:55 exchange rate at 1.81) is falsified outright. (ii) The V ladder: flat 0.50 kills delta > 0. (iii) M99 vs M98: any reliable cliff-sized drop inside balanced coalitions falsifies w99-w98 <= 0.044. (iv) G1 anchor (A wins 0.95/0.90/0.85/0.75/0.65 vs three 0.55s): FDEI box [.811,.918] core, BSST [.761,.786] -- p(G1) <= 0.77 strains FDEI, p(G1) >= 0.80 exceeds BSST's ceiling. CONTROLS: X1 (one 0.55 won by each side, everything else tied): BOTH theories must predict exactly 0.50 for every parameter -- a side/display-bias assay. R1 vs V4 is a surface-invariance check both theories demand (identical evidence w95-w55, different surface: 1-vs-1 vs 2-vs-2 discriminators) -- inequality would indicate count-based heuristics outside both models. Tie patterns mix 0/0 and 1/1 so 'count the 1s' is unviable (e.g., M98 shows A with five 1s vs B with three 1s while the theories nearly tie; G1m shows B with six 1s vs A with three). No all-tie trials; every trial has 2-7 discriminators among 10 experts requiring genuine scanning. Sides balanced (10 A-tilted / 9 B-tilted / 5 near-neutral under FDEI centers; every non-anchor family contains an A/B mirror). PREDICTED PATTERN IF FDEI IS RIGHT (centers): R1 .564, R2 .573, R3 .441, R4 .450, R5 .577, R6 .454, V4<V1<V2<V3 = .564/.588/.601/.612, M98 .482 = M99 .486, P95 .512 > P55 .448, G1 .872, X1 .500 -- a rising plateau psychometric, near-zero cliff sensitivity, several-points plateau sensitivity, crossovers between k=1 and k=2. IF BSST IS RIGHT: R1/V1-V4 exactly .500, R2 .457, R3 .351, R4 .313, R5 .204, R6 .122, M98 .457 >> M99 = P95 = P55 = .204 exactly, G1 .774, X1 .500 -- flat plateau psychometric, zero plateau sensitivity, massive cliff sensitivity, never following a 0.98/0.99 expert. The boxes are disjoint or parameter-free-separated on 16 of 24 cells, and the two sensitivity orderings are mutually exclusive.

**Computed schedule:** 24 unique pairs × 4 reps = 96 trials per subject.



### METRIC
Rationale:
The single sharpest, most robust structural disagreement between FDEI and BSST in this design is the sign of the weight assigned to the 0.99-validity expert. FDEI's compressed-but-strictly-monotone weight function makes w(0.99) its LARGEST positive weight (about 1.16-1.36 cue units across its whole parameter box), so whenever the 0.99 expert discriminates, FDEI follows it above chance. BSST's distrust cliff makes w(0.99) strongly NEGATIVE (about -0.9 to -1.3 across its whole box), so BSST systematically chooses AGAINST the 0.99-endorsed option. In this 24-trial schedule, exactly 8 unique trials (trials 7, 8, 9, 17, 18, 19, 20, 21) have the feature-1 (0.99) expert discriminating; in every one of them the remaining discriminating cues form a balanced or weak background (mid-band cues split across sides, plus 0.5/0.55-flank cues that are near-zero under FDEI), so the 0.99 cue carries the sign of the evidence. With 4 repetitions this yields 32 informative trials per subject. Predicted values: FDEI ~0.62 (every parameter in its box gives follow-rates of roughly 0.56-0.73 on these trials, plus a small lapse pulling toward 0.5); BSST ~0.15-0.35 (anti-following on all 8 trial types under either the 0.5 or 0.55 flank-validity reading of the design, since the cliff weight dominates the balanced background). The gap (~0.3 in means) is large relative to per-subject sampling noise (binomial SD over 32 trials is about 0.08), so with N=25 subjects Welch's t-test separates the theories decisively. The metric is a plain behavioral proportion (no model fitting, no free parameters), works identically on the pooled data and on each single subject's slice, and is deliberately insensitive to the mid-band weight structure, the softmax gain, and the exact flank validities — it isolates exactly the one qualitative signature (follow vs. anti-follow a 99% expert) on which the two theories make opposite-signed, box-uniform predictions. It is not trivially true for FDEI: it is precisely the empirical claim at stake — that stated near-certainty is trusted (compressed, but not inverted) rather than distrusted — and a human follow-rate at or below 0.5 on these trials would falsify FDEI's entire parameter box.

Source:
def metric(data: pd.DataFrame) -> float:
    # "Follow-the-99%-expert rate": across all trials where the single
    # 0.99-validity expert (feature index 0 in the fixed validity vector
    # [0.99, 0.98, 0.95, 0.90, 0.85, 0.75, 0.65, ., ., .]) discriminates
    # between A and B, compute the proportion of choices that go to the
    # option the 0.99 expert rated 1 (i.e., the option the top expert
    # "endorsed").
    #
    # FDEI: w(0.99) is the LARGEST positive weight in the whole vector
    # (its compression never inverts the validity ordering), so the
    # 0.99-favored option is followed above chance on essentially every
    # such trial -> metric ~ 0.60-0.65.
    # BSST: w(0.99) is strongly NEGATIVE (~ -1.1 trusted-cue units, the
    # distrust cliff), so the 0.99-favored option is chosen BELOW chance
    # on every such trial (the background cues are balanced/weak in this
    # design) -> metric ~ 0.15-0.35.
    # The sign of (metric - 0.5) alone separates the two theories on
    # every trial in the 0.99-discriminating set.

    TOP = 0  # index of the 0.99-validity expert, fixed by the design

    resp = data['response'].to_numpy()
    follows = []

    for i in range(len(data)):
        a_raw = data['option_a_ratings'].iloc[i]
        b_raw = data['option_b_ratings'].iloc[i]
        try:
            av = np.asarray(list(a_raw), dtype=int).ravel()
            bv = np.asarray(list(b_raw), dtype=int).ravel()
        except Exception:
            continue
        if av.size <= TOP or bv.size <= TOP:
            continue

        d = int(av[TOP]) - int(bv[TOP])
        if d == 0:
            continue  # 0.99 expert tied on this trial -> uninformative

        favored_a = d > 0          # option the 0.99 expert endorsed
        chose_a = (int(resp[i]) == 0)
        follows.append(1.0 if (chose_a == favored_a) else 0.0)

    if len(follows) == 0:
        return 0.5  # neutral fallback (should not occur: 8 trials x 4 reps)

    return float(np.mean(follows))

### RESULTS
- Predicted under pi_6 (simulated): 0.2988 (var=0.0058)
- Predicted under pi_4 (simulated): 0.6719 (var=0.0085)
- Observed on real data: 0.5988 (var=0.0026)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    rows_a = data["option_a_ratings"].tolist()
    rows_b = data["option_b_ratings"].tolist()
    resp = data["response"].tolist()
    n_rows = len(rows_a)
    contribs = []
    for i in range(n_rows):
        ca = rows_a[i]
        cb = rows_b[i]
        if isinstance(ca, str):
            ca = ca.replace("[", " ").replace("]", " ").replace(",", " ").split()
        if isinstance(cb, str):
            cb = cb.replace("[", " ").replace("]", " ").replace(",", " ").split()
        a = [int(float(v)) for v in ca]
        b = [int(float(v)) for v in cb]
        r = int(resp[i])
        n = len(a)
        if n == 0 or n != len(b):
            continue
        ttb = -1
        for j in range(n):
            if a[j] > b[j]:
                ttb = 0
                break
            if b[j] > a[j]:
                ttb = 1
                break
        if ttb < 0:
            continue
        aw = 0
        bw = 0
        for j in range(n):
            if a[j] > b[j]:
                aw = aw + 1
            elif b[j] > a[j]:
                bw = bw + 1
        if aw == bw:
            if r == ttb:
                contribs.append(0.5)
            else:
                contribs.append(-0.5)
        else:
            if bw > aw:
                tal = 1
            else:
                tal = 0
            if tal == ttb:
                continue
            if r == ttb:
                contribs.append(1.0)
            else:
                contribs.append(-1.0)
    if len(contribs) == 0:
        return 0.0
    total = 0.0
    for c in contribs:
        total = total + c
    return float(total / len(contribs))
```

**Observed (real) value:** -0.2180 (var=0.0140)
**Predicted under pi_6:** -0.1973 (var=0.0076)
**Predicted under pi_4:** -0.2188 (var=0.0064)

### Experiment 4
**Design**
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Dual-dissociation regression metric.
    # Per trial, compute:
    #   d = tally margin  = (#features A wins) - (#features B wins)
    #   s = top-cue direction = sign(A[0] - B[0])   (feature 0 has the
    #       highest validity 0.92, and every designed pair discriminates on it)
    # Regress chose-A on [1, d, s] via OLS and return b_d - b_s.
    # Tallying: choice probability depends only on d  -> b_d > 0, b_s = 0 -> metric > 0.
    # TTB: choice probability depends only on s       -> b_d = 0, b_s > 0 -> metric < 0.
    # The two theories push this scalar in opposite directions, and the
    # partial regression cleanly removes the design's d-s correlation.
    df = data.reset_index(drop=True)

    A = np.stack([np.asarray(list(r), dtype=float) for r in df["option_a_ratings"].values])
    B = np.stack([np.asarray(list(r), dtype=float) for r in df["option_b_ratings"].values])

    # Tally margin: strict feature-wise wins; ties count for neither side.
    d = (A > B).sum(axis=1).astype(float) - (B > A).sum(axis=1).astype(float)

    # Direction of the highest-validity (top) cue, which always discriminates
    # in this design: +1 if it favors A, -1 if it favors B.
    s = np.sign(A[:, 0] - B[:, 0])

    # Chose-A indicator (response: 0 = A, 1 = B).
    y = 1.0 - df["response"].to_numpy(dtype=float)

    X = np.column_stack([np.ones(len(y)), d, s])
    coef, _, _, _ = np.linalg.lstsq(X, y, rcond=None)
    b_d = float(coef[1])
    b_s = float(coef[2])

    # Tallying's signature (slope in d) minus TTB's signature (slope in s).
    return b_d - b_s
```

**Observed (real) value:** 0.0771 (var=0.0031)
**Predicted under pi_6:** 0.0956 (var=0.0023)
**Predicted under pi_4:** 0.0881 (var=0.0019)

### Experiment 5
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Tally-following rate on decisive trials.

    For every trial, compute the raw (unweighted) tally margin
    d = (# cues where A wins) - (# cues where B wins).
    On trials with d != 0, check whether the subject's choice agrees
    with the option favored by the raw cue count (A if d > 0, B if
    d < 0). The metric is the fraction of such agreement over all
    decisive trials (d = 0 trials are excluded because the tallying
    heuristic itself is indifferent there).
    """
    df = data.reset_index(drop=True)
    n = len(df)
    if n == 0:
        return 0.5

    a_lists = df['option_a_ratings'].tolist()
    b_lists = df['option_b_ratings'].tolist()
    resp = df['response'].to_numpy(dtype=float)

    d = np.empty(n, dtype=float)
    for i in range(n):
        a = np.asarray(a_lists[i], dtype=float)
        b = np.asarray(b_lists[i], dtype=float)
        d[i] = float(np.sum(a > b) - np.sum(b > a))

    decisive = d != 0.0
    if not np.any(decisive):
        return 0.5

    dd = d[decisive]
    rr = resp[decisive]
    # Option favored by the raw tally: A (response 0) if d > 0,
    # otherwise B (response 1).
    agree = np.where(dd > 0.0, rr == 0.0, rr == 1.0)
    return float(np.mean(agree))
```

**Observed (real) value:** 0.6170 (var=0.0034)
**Predicted under pi_6:** 0.4811 (var=0.0035)
**Predicted under pi_4:** 0.6485 (var=0.0027)

### Experiment 6
**Design**
  A=[1, 1, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 0, 0, 0]  B=[1, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 1, 0, 0, 1]  B=[1, 1, 1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Hard-ceiling test on the |d|=1 family (FACT 1 of the design).

    Metric = proportion of choices that agree with the UNWEIGHTED tally
    count-winner, restricted to trials whose raw tally margin is exactly
    +/-1 (the 8 trial types t1-t8; 48 of the 96 trials per subject).

    Tallying (any beta >= 1, any epsilon) predicts ~1 - epsilon/2 here,
    i.e. >= ~0.85 for any moderate lapse. The validity-weighted
    competitor is structurally capped: its choice probability on a |d|=1
    trial is (1-eps)*sigmoid(2*beta*m) with m = sum_j v_j^gamma*sign diff;
    the mean of |m| over the 8 |d|=1 trial types is <= 1 for every
    gamma in [0.05, 0.7] (equality only at gamma=0), and beta <= 0.55,
    so by concavity of tanh its mean agreement on this family is
    <= 0.5 + tanh(0.55)/2 = 0.750 over its ENTIRE parameter box.
    """
    def _mat(col):
        vals = []
        for v in col:
            if isinstance(v, np.ndarray):
                vals.append(v)
            else:
                vals.append(list(v))
        return np.asarray(vals, dtype=float)

    A = _mat(data["option_a_ratings"])
    B = _mat(data["option_b_ratings"])
    resp = np.asarray(data["response"], dtype=float)

    if A.ndim != 2 or A.shape[0] == 0 or A.shape != B.shape:
        return 0.5

    # Raw (unweighted) tally margin per trial.
    d = (A > B).sum(axis=1) - (B > A).sum(axis=1)

    # The |d| = 1 family: 8 unique pairs x 6 reps = 48 trials/subject.
    mask = np.abs(d) == 1
    if mask.sum() < 10:
        # Defensive fallback: use all non-tied trials.
        mask = d != 0
    if mask.sum() == 0:
        return 0.5

    dm = d[mask]
    rm = resp[mask]
    # Count-winner is A when d>0 (response 0), B when d<0 (response 1).
    consistent = np.where(dm > 0, rm == 0, rm == 1)
    return float(np.mean(consistent))
```

**Observed (real) value:** 0.5133 (var=0.0042)
**Predicted under pi_6:** 0.3850 (var=0.0041)
**Predicted under pi_4:** 0.5192 (var=0.0023)

### Experiment 7
**Design**
  A=[1, 0, 1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1, 0, 1]  B=[1, 1, 0, 1, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 1]  B=[1, 1, 1, 1, 0, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    # Chance-cue sensitivity on "chance-only" (Z-family) trials.
    # Design validities: [0.95, 0.85, 0.75, 0.65, 0.5, 0.5, 0.5, 0.5]
    # -> features 0-3 are diagnostic, features 4-7 are the four v=0.5 experts.
    # A Z-family trial is one where ALL diagnostic cues tie, so the pair is
    # discriminated ONLY by the 50%-accurate experts. On such a trial let
    # k = net number of chance cues won by A (signed). The competing theory
    # (llr-rectified weights) annihilates v=0.5 cues exactly, so p(A)=0.5
    # regardless of k -> subjects match the k-implied side at chance (metric 0).
    # My theory gives v=0.5 cues weight 0.5^gamma, so choices should follow
    # sign(k) above chance (metric > 0).
    DIAG = [0, 1, 2, 3]
    CHANCE = [4, 5, 6, 7]

    a_ratings = data["option_a_ratings"].apply(lambda x: np.asarray(list(x), dtype=int))
    b_ratings = data["option_b_ratings"].apply(lambda x: np.asarray(list(x), dtype=int))
    responses = data["response"].to_numpy()

    correct = []
    for av, bv, r in zip(a_ratings, b_ratings, responses):
        if av.shape[0] != 8 or bv.shape[0] != 8:
            continue
        # Keep only trials where every diagnostic cue ties (chance-only trials)
        if not np.array_equal(av[DIAG], bv[DIAG]):
            continue
        # Net chance-cue advantage for A
        k = int(np.sign(av[CHANCE] - bv[CHANCE]).sum())
        if k == 0:
            continue
        chose_a = (int(r) == 0)  # response: 0 = A, 1 = B
        followed = (k > 0 and chose_a) or (k < 0 and not chose_a)
        correct.append(1.0 if followed else 0.0)

    if len(correct) == 0:
        return 0.0
    # 2 * (accuracy - 0.5): 0 = chance-level following of chance cues,
    # positive = subjects systematically follow the 50%-accurate experts.
    return 2.0 * (float(np.mean(correct)) - 0.5)
```

**Observed (real) value:** -0.1683 (var=0.0124)
**Predicted under pi_6:** -0.1350 (var=0.0257)
**Predicted under pi_4:** 0.0308 (var=0.0233)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Strong-Side Choice Rate on Multi-Weak Conflict trials (SSR).

    Selects the five conflict cells in which a high-validity side (99%
    experts, or 75% experts for R3) faces TWO OR MORE opposing weak
    experts: K2 (1x99 vs 2 weak), K3 (1x99 vs 3 weak), M3 (2x99 vs 3
    weak), M4 (2x99 vs 4 weak), R3 (2x75 vs 3 weak) -- 5 unique pairs
    x 2 mirrors x 4 reps = 40 trials per subject. Returns the
    proportion of trials on which the subject chose the strong side.
    """
    hits = 0
    n = 0

    a_col = data['option_a_ratings']
    b_col = data['option_b_ratings']
    r_col = data['response']

    for a, b, r in zip(a_col, b_col, r_col):
        a = [int(x) for x in a]
        b = [int(x) for x in b]
        if len(a) < 8 or len(b) < 8:
            continue

        # Validity-class vote balances (features 0-1 = 0.99 experts,
        # 2-3 = 0.75 experts, 4-7 = weak experts).
        d_hi = (a[0] + a[1]) - (b[0] + b[1])
        d_mid = (a[2] + a[3]) - (b[2] + b[3])
        d_lo = (a[4] + a[5] + a[6] + a[7]) - (b[4] + b[5] + b[6] + b[7])

        # K2/K3/M3/M4: super experts alone on one side (no 75s involved)
        # opposing >= 2 weak experts.
        if d_mid == 0 and d_hi != 0 and abs(d_lo) >= 2:
            target_is_a = d_hi > 0
        # R3: two 75% experts vs three weak experts.
        elif d_hi == 0 and abs(d_mid) == 2 and abs(d_lo) == 3:
            target_is_a = d_mid > 0
        else:
            # Excludes K1 (|d_lo|=1), R1, W2/W3 (no strong side),
            # W4a (|d_mid|=1), G1 (mixed 99+75 side), X1 (all tied).
            continue

        n += 1
        chose_a = (int(r) == 0)
        if chose_a == target_is_a:
            hits += 1

    if n == 0:
        return 0.5
    return hits / n

```

**Observed (real) value:** 0.1180 (var=0.0074)
**Predicted under pi_6:** 0.4360 (var=0.0065)
**Predicted under pi_4:** 0.7670 (var=0.0039)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Super-expert contrarianism index.

    Over all trials in which the feature-0 expert (the 99%-validity
    expert) discriminates between the two options (a[0] != b[0]),
    compute the proportion of choices that go AGAINST the option
    endorsed by that expert.

    Advocated theory (inverted trust): the 99% expert's endorsement is
    anti-diagnostic (w(0.99) ~ -1 trusted-cue unit), so subjects
    predominantly choose AGAINST it -> index ~0.8-0.9.

    Competing theory (flattened diagnosticity): the 99% expert gets the
    LARGEST positive weight, so subjects predominantly FOLLOW it ->
    index ~0.2-0.35.
    """
    n_anti = 0
    n_sel = 0
    for ra, rb, resp in zip(
        data["option_a_ratings"], data["option_b_ratings"], data["response"]
    ):
        a = np.asarray(ra, dtype=int).ravel()
        b = np.asarray(rb, dtype=int).ravel()
        if a.size == 0 or b.size == 0 or a[0] == b[0]:
            continue  # expert 0 does not discriminate on this trial
        # Option index endorsed by the 99%-validity (feature-0) expert.
        endorsed = 0 if a[0] == 1 else 1
        r = int(resp)
        n_sel += 1
        if r != endorsed:
            n_anti += 1
    if n_sel == 0:
        return 0.5
    return float(n_anti) / float(n_sel)

```

**Observed (real) value:** 0.5796 (var=0.0066)
**Predicted under pi_6:** 0.6756 (var=0.0042)
**Predicted under pi_4:** 0.3191 (var=0.0050)

### Experiment 10
**Design**
  A=[1, 1, 0, 0, 1, 0, 0, 1, 0]  B=[1, 0, 0, 1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 1, 1, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 0, 1, 0, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 0, 1, 0, 0]  B=[1, 0, 0, 1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 0, 0, 1, 0]  B=[1, 0, 0, 1, 1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 1, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 1, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """P(follow the 98% expert | 98%-vs-90% conflict trials).

    A 'D-cell' trial is one where the top expert (v=0.98, feature 0) and the
    second expert (v=0.90, feature 1) endorse OPPOSITE options, while the
    third expert (v=0.75, feature 2) is tied. On these trials the metric is
    the fraction of choices that follow the option endorsed by the 98%
    expert. FDEI (compressed diagnosticity) treats 0.98 and 0.90 as nearly
    exchangeable, so this should be ~0.50 (coin flip). SITT (inverted trust)
    assigns the 98% expert a large NEGATIVE weight, so subjects should
    systematically choose AGAINST the 98% endorsement (~0.05-0.10).
    """
    if data is None or len(data) == 0:
        return 0.5

    follow_flags = []
    for _, row in data.iterrows():
        a = np.asarray(row["option_a_ratings"], dtype=float)
        b = np.asarray(row["option_b_ratings"], dtype=float)
        if a.ndim != 1 or a.shape[0] < 3 or a.shape != b.shape:
            continue

        d0 = a[0] - b[0]  # 98% expert's relative endorsement of A
        d1 = a[1] - b[1]  # 90% expert's relative endorsement of A
        d2 = a[2] - b[2]  # 75% expert must be tied (no interference)

        # Need a genuine 98-vs-90 conflict with the 75% expert tied.
        if d0 == 0 or d1 == 0 or d2 != 0:
            continue
        if np.sign(d0) == np.sign(d1):
            continue

        endorsed_a = d0 > 0          # 98% expert endorses option A
        chose_a = (int(row["response"]) == 0)
        follow_flags.append(1.0 if (endorsed_a == chose_a) else 0.0)

    if len(follow_flags) == 0:
        return 0.5
    return float(np.mean(follow_flags))
```

**Observed (real) value:** 0.4625 (var=0.0103)
**Predicted under pi_6:** 0.4213 (var=0.0156)
**Predicted under pi_4:** 0.5400 (var=0.0192)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Taking all ten experiments together, neither theory is task-invariant; each is falsified by a distinct subset of the data, and one experiment (Exp 8) breaks both catastrophically.\n\nWhere pi_4 (FDEI) wins: Exps 1-6. It is essentially exact on Exps 3 (-0.219 vs -0.218) and 4 (0.088 vs 0.077), close on Exp 5 (0.649 vs 0.617) and Exp 6 (0.519 vs 0.513), and far better on Exps 1 (0.40 vs observed 0.56; pi_6 off by 0.25) and 2 (0.672 vs observed 0.599; pi_6 predicts 0.30 \u2014 a sign error on its flagship cliff). FDEI correctly captures the core integration signature: near-tally, moderately graded, low-gain behavior.\n\nWhere pi_6 (BSST) wins: Exps 7, 9, 10, and (weakly) 8. Its chance-flank direction is confirmed (Exp 7: observed -0.168 vs pi_4's +0.031 \u2014 FDEI's exact annihilation of v=0.5 cues is falsified), and its anti-super-expert direction is confirmed (Exp 9: observed 0.580 anti-99 vs pi_4's 0.319; Exp 1: 0.560 anti-99). But its magnitudes are badly miscalibrated: the sharp 0.98/0.99 cliff (w(0.99) \u2248 -1.1) predicts anti-99 rates of 0.68-0.81 where the data show only 0.56-0.58, and it fails the core tally behavior outright (Exp 5: 0.481 vs 0.617; Exp 6: 0.385 vs 0.513).\n\nThe catastrophic joint failure is Exp 8: observed strong-side rate 0.118 vs pi_6's 0.436 and pi_4's 0.767. Subjects chose the multi-cue weak side ~88% of the time against 99% experts \u2014 near the lapse floor. Neither an inverted cliff of -1.1 (would give ~0.2-0.3, not 0.44 as simulated on this mix) nor a trusted-largest-weight 99 expert (0.767) can produce this.\n\nThe emergent empirical profile across all ten experiments is: (a) approximately EQUAL positive weights over the diagnostic mid-band (Exps 2-6, 8: tally-like counting, |d|=1 agreement only 0.51, multi-cue margins followed strongly); (b) a small NEGATIVE weight on stated-chance experts (Exp 7: -0.168 \u2014 BSST's one well-calibrated piece); (c) distrust of near-certainty claims that is CONTEXT-DEPENDENT, not absolute: the 99% expert is mildly followed when embedded in a dense high-validity ladder (Exp 2, next-best 0.98 \u2192 follow 0.60), but discounted toward zero (or beyond) when an isolated outlier above a much weaker panel (Exps 8, 9, next-best \u2248 0.75 \u2192 anti-99 0.58, strong-side rate 0.118); (d) 0.98 and 0.90 are nearly exchangeable when adjacent in a ladder (Exp 10: 0.4625). BSST's absolute 0.98/0.99 cliff cannot reconcile Exp 2 with Exps 8/9; FDEI's monotone compression cannot reconcile Exp 2 with Exps 7/8/9. A relative/consensus-anchored distrust mechanism is required. Since pi_4 is the front-runner on experiment count but is still falsified on four experiments (one catastrophically), and pi_6 is falsified on the core, the correct move is to replace the weaker theory (pi_6) with a new theory that unifies these signatures and serves as a stronger competitor to pi_4.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace pi_6 with 'Consensus-Relative Edge-Distrust Tallying' (CREDT). Keep the shared, well-supported architecture (sign votes \u00d7 validity weights \u00d7 low-gain softmax \u00d7 lapse) \u2014 that scaffold is endorsed by every experiment. Replace the weight function with three components: (1) MID-BAND PLATEAU WITHOUT A CLIFF: all cues with stated validity in [v_lo, v_hi] (v_lo \u2248 0.55, v_hi \u2248 0.96) receive approximately equal positive weight w_p \u2248 1 \u2014 pure tally behavior over diagnostic cues (recovers Exps 2-6, 10). There is NO absolute 0.98/0.99 discontinuity; adjacent high validities are near-exchangeable. (2) CHANCE-FLANK: a small negative weight for v near 0.5, w(0.5) = -kappa_lo with kappa_lo in [0.15, 0.25] \u2014 the one BSST component the data confirm (Exp 7: observed -0.168). (3) THE NOVEL PIECE \u2014 OUTLIER-GAP DISTRUST: the subjective weight of the top expert(s) is modulated by the gap between the highest stated validity and the next-highest validity in the panel (computable from parameters['validities']). Small gap (dense ladder, e.g., 0.99 atop 0.98/0.95/0.90 as in Exp 2) \u2192 the top cue keeps ~full plateau weight (predicts follow-99 \u2248 0.58-0.62, matching observed 0.599). Large gap (isolated outlier, e.g., 0.99 atop 0.75 as in Exps 8/9) \u2192 its weight collapses toward zero or slightly negative via w_top = w_p - rho * sigmoid((gap - g0)/s), with g0 \u2248 0.05-0.10, rho allowing the asymptote to reach [-0.6, +0.1] (predicts Exp 8 strong-side rate \u2248 0.08-0.20 near the lapse floor, and Exp 9 anti-99 \u2248 0.52-0.60, matching observed 0.580). Suggested parameters: w_p \u2208 [0.8, 1.2], v_lo \u2208 [0.52, 0.58], v_hi \u2208 [0.95, 0.97], kappa_lo \u2208 [0.15, 0.25], g0 \u2208 [0.04, 0.12], s \u2208 [0.02, 0.06], rho \u2208 [0.9, 1.7], beta \u2208 [0.30, 0.50], epsilon \u2208 [0.03, 0.08]. This theory differs from BSST by making distrust of certainty RELATIVE to the panel consensus rather than an absolute cliff, and differs from FDEI by (i) keeping chance cues anti-diagnostic rather than annihilated and (ii) capping the influence of isolated super-experts rather than giving them the largest positive weight. It should simultaneously recover the tally core (Exps 2-6), the chance-flank negativity (Exp 7), the isolated-outlier distrust (Exps 1, 8, 9), and 98/90 exchangeability (Exp 10), making it a genuine task-invariant competitor to FDEI."
}
```

## Usage

```json
{
  "input_tokens": 27343,
  "output_tokens": 19691,
  "reasoning_tokens": 18007,
  "provider": "Sail Research"
}
```
