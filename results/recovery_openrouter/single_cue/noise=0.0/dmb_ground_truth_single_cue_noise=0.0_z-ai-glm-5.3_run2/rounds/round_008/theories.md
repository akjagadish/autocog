# Round 8 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_7` — SURVIVED ✓

**Description:** Anti-Validity Frugality with Diffuse Positional-Salience Heterogeneity (momentary-diffusion variant). People are one-reason decision makers: cues are consulted one at a time in descending subjective weight and the first strictly discriminating cue decides; no integration across cues (flat psychometric profile over tally margins). The population-central hierarchy is anti-validity (distrust-the-weakest, w = -validity). Each subject's weights are a continuous perturbation, w_j = -val_j + gamma*salience_j + A^3*(sigma_h*zeta_j + kappa*xi_j), where (i) salience_j is a positional gradient favoring early-listed experts with gamma drawn asymmetrically from [-0.05, +0.12] — a graded tilt, never a discrete primacy rule, bounded so it can flip nothing on the anchored designs that pin the anti-validity core; (ii) binding ambiguity A = 1 - |Spearman(position, validity)| enters CUBED, a steeply convex, gate-free gradient; and (iii) the idiosyncratic distortion is split into a small stable part (zeta_j, fixed per subject) and a large MOMENTARY part (xi_j, re-drawn every trial): under high binding ambiguity the consultation order is not merely idiosyncratic but diffuse — attention fluctuates from trial to trial, which keeps populations tight around chance-level conformity instead of spreading subjects into fixed opposing deciders. All distortion applies only when all advertised validities are distinct (exact ties anchor the distrust order). Noise is softmax(beta) over the binary winner score plus an independent lapse epsilon (implied follow p_f mean ~0.71, SD ~0.08); no discriminating cue yields exactly 0.5; validity ties are broken by a free per-subject tie-break (~80% early position); history is ignored.

**Rationale:** Minimal-diff edit of the ACCEPTED base (loss 0.0915), addressing the critic's (A)-(E) with one structural addition my own moment audit shows is necessary. (A) PATHWAY VERIFICATION — the critic suspects zeta is silently zeroed. It is not: a zeta-zeroed model (pure anti-validity core at this p_f regime, mean ~0.71) produces an Exp-10 index near the pi_4 level (~590), while the simulation returns 241; moreover iter-1 (weaker sigma_h, linear A) gave 255 and iter-2 (nearly doubled sigma_h, A-squared) gave 241 — a SATURATED lever, not an inert one. I did remove the silent zeros fallback (it now raises), so any future shape mismatch fails loudly. (B) THE REAL Exp-10 DIAGNOSIS — the residual +124 is carried by the dispersion term: our per-subject var is 0.0134 vs observed 0.0041. With FIXED per-subject consultation orders, scrambling MAXIMIZES between-subject follow-rate dispersion (each subject's order deterministically flips or matches each cue pair, giving between-subject SD ~0.13-0.17); the observed SD 0.064 sits barely above the binomial floor (0.053 at ~90 trials). No recalibration of a fixed zeta — including the critic's suggested sigma_h [0.6,1.2] with zeta +/-1, which by my pair-flip calculation still lands near ~200 — can produce a tight, chance-centered population. The fix: split the distortion into a small STABLE part (sigma_h*zeta, exactly the critic's suggested range) plus a large MOMENTARY per-trial diffusion (kappa*xi, fresh every trial). This keeps every pooled-mean metric identical to the fixed-zeta version (means are linear in the noise distribution) while collapsing the between-subject Gini to the binomial floor plus a small stable component. Moment math on Exp 10 (A=0.857, A^3=0.63, kappa~10 -> per-cue noise std ~3.6): mean follow ~0.505, per-subject SD ~0.06 -> index ~100-135 (observed 116.6, var ~0.004) instead of 241. On Exp 12 (A^3=0.32, noise ~1.9): analytic full-diffusion follow = 0.535 vs observed 0.532. I steepened the gradient from A^2 to A^3 so that Exp 9 (A=0.23, A^3~0.012 -> noise ~0.08, close to its current ~0.15) stays anchored at its excellent current fit (0.416 vs 0.428); a linear or quadratic scaling at Exp-10-appropriate magnitude would over-scramble Exp 9 toward 0.5. (C) Exp 4 — adopted the critic's asymmetric gamma [-0.05, +0.12] verbatim: the floor sits above the anchored-design flip threshold (-0.0625) and the cap below the Exp-14 primacy threshold (+0.144), so Exp 14 stays exactly 0.000 with var 0 and Exp 7 keeps its recovered opposition while a positive tail partially restores the early-position lean the gamma tightening removed. (D) GATE RELAXATION REJECTED, with a cell-level audit: on Exp 8 (tied, A=0.77) all four margin-0 deciders ALREADY oppose the reversed hierarchy — the model sits at the family's maximum opposition (1-p_f ~ 0.27; observed -0.289 exceeds even that), so dispersion can only wash it toward 0; on Exp 13 (tied, A=0.91) the observed 0.150 lies BELOW the pure-opposition floor 1-p_f ~ 0.29, and noise drifts the metric UP toward 0.5; on Exp 7 dispersion washes the signed contrast toward 0, the wrong direction from -0.196 vs observed -0.311. Only Exp 5 would benefit, and it cannot outweigh three regressions; I also verified the tie-break is inert on the metric cells of Exps 5, 6, 7, 11 and 13. (E) p_f untouched (mean ~0.71, SD ~0.08): Exp 3 pins it at 0.727 and the de-conformity on Exps 10/12 now comes from decider diffusion, not response weakness. Acknowledged family limits left in place: Exps 13 and 7 (observed opposition beyond 1-p_f), Exp 5 (tied-design over-conformity, unfixable without the rejected gate relaxation), Exp 1 (TTB-following level pinned near 1-p_f). Expected net movement: Exp 10 from +124 to roughly 0 +/- 20, Exp 12 from +0.037 to ~0, Exp 4 recovery toward +0.04 if the gamma mechanism is as the critic's audit indicates, with Exps 2, 3, 5, 6, 8, 9, 11, 13, 14 preserved — comfortably below the accepted loss floor.

**Parameters:**
  - `beta`: `[0.5, 1.9]`
  - `epsilon`: `[0.08, 0.24]`
  - `gamma`: `[-0.05, 0.12]`
  - `sigma_h`: `[0.6, 1.2]`
  - `kappa`: `[8, 12]`
  - `zeta`: `[(-1, 1)] * n_features`
  - `tie_break`: `[0, 1]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Anti-Validity Frugality with Diffuse Positional-Salience Heterogeneity
    # (momentary-diffusion variant).
    #
    # One-reason decision making: cues are consulted one at a time in
    # DESCENDING subjective weight and the first strictly discriminating
    # cue decides; no integration across cues (flat psychometric profile
    # over tally margins).
    #
    # Subjective weights (continuous, per subject):
    #     w_j = -val_j + gamma * salience_j
    #            + A^3 * (sigma_h * zeta_j + kappa * xi_j)
    #
    # - ANTI-VALIDITY CORE: -val_j (distrust the weakest advertised
    #   expert; consult ascending validity).
    # - POSITIONAL SALIENCE: salience_j = (n-1-j)/(n-1) - 1/2, favoring
    #   early-listed experts; gamma is drawn ASYMMETRICALLY from
    #   [-0.05, +0.12]: the negative clamp sits above the anchored-design
    #   flip threshold (-0.0625) and the positive cap below the primacy
    #   type threshold (+0.144), so the tilt remains a graded perturbation
    #   that can never manufacture spurious pure types while retaining a
    #   partial early-position lean on anchored designs.
    # - BINDING AMBIGUITY: A = 1 - |Spearman(display position, validity)|,
    #   now entering CUBED. The steeply convex gradient keeps
    #   low/moderate-ambiguity designs anchored (A^3 ~ 0.01-0.02) while
    #   fully diffusing high-ambiguity all-distinct designs (A^3 ~ 0.3-0.6).
    # - DIFFUSE HETEROGENEITY: the idiosyncratic distortion is split into
    #   (a) a SMALL STABLE part, sigma_h * zeta_j (zeta fixed per subject,
    #   zero-centered), and (b) a LARGE MOMENTARY part, kappa * xi_j,
    #   where xi is RE-DRAWN EVERY TRIAL. Momentary consultation diffusion
    #   is what makes high-ambiguity populations tight around chance-level
    #   conformity: with fixed per-subject orders, scrambling MAXIMIZES
    #   between-subject follow-rate dispersion, whereas the observed
    #   population SD (~0.064 on the conformity-dispersion experiment)
    #   sits barely above the binomial floor. Both parts are applied ONLY
    #   when all advertised validities are distinct (exact ties anchor the
    #   distrust order).
    # NO reversal re-encoding, NO sigmoid gates, NO discrete component
    # draws.
    #
    # Noise: softmax(beta) over the binary winner score mixed with an
    # independent lapse epsilon (implied follow probability
    # p_f = (1-eps)*sigmoid(beta) + eps/2, mean ~0.71, SD ~0.08).
    # No discriminating cue -> exactly 0.5. History is ignored.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float).ravel()
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    gamma = float(parameters["gamma"])
    sigma_h = float(parameters["sigma_h"])
    kappa = float(parameters["kappa"])
    tie_break = float(parameters["tie_break"])

    zeta = np.asarray(parameters["zeta"], dtype=float).ravel()
    if zeta.shape[0] != n_features:
        # NO silent zeros fallback: a shape mismatch means the entire
        # heterogeneity mechanism would be silently disabled, so fail
        # loudly instead (per the arbiter's diagnosis request).
        raise ValueError(
            f"zeta length {zeta.shape[0]} != n_features {n_features}."
        )

    # ---- helper: average-tie ranks ----
    def avg_ranks(x):
        n = x.shape[0]
        srt = np.argsort(x, kind="stable")
        ranks = np.empty(n, dtype=float)
        i = 0
        while i < n:
            j = i
            while j + 1 < n and x[srt[j + 1]] == x[srt[i]]:
                j += 1
            ranks[srt[i:j + 1]] = 0.5 * (i + j)  # 0-indexed average rank
            i = j + 1
        return ranks

    # ---- positional-salience gradient (early-listed experts favored) ----
    # Centered so the tilt is a pure graded perturbation: +0.5 at the
    # first listed expert, -0.5 at the last, linear in between.
    if n_features > 1:
        sal = ((n_features - 1 - np.arange(n_features, dtype=float))
               / (n_features - 1.0)) - 0.5
    else:
        sal = np.zeros(1, dtype=float)

    # ---- binding ambiguity: A = 1 - |Spearman(position, validity)| ----
    if n_features > 1:
        ranks = avg_ranks(val)
        pos_r = np.arange(n_features, dtype=float)
        vp = pos_r - pos_r.mean()
        vr = ranks - ranks.mean()
        denom = np.sqrt(float((vp * vp).sum()) * float((vr * vr).sum()))
        if denom > 1e-12:
            rho = float((vp * vr).sum()) / denom
        else:
            # All validities tied: distrust order undefined.
            rho = 0.0
        ambiguity = 1.0 - abs(rho)
    else:
        ambiguity = 0.0

    # ---- continuous subjective weights ----
    w = -val + gamma * sal

    # ---- diffuse idiosyncratic distortion (distinct lists only) ----
    # Exact validity ties anchor the distrust order (no distortion);
    # all-distinct lists degrade with the CUBE of binding ambiguity.
    # The distortion is split into a small STABLE per-subject part
    # (sigma_h * zeta) and a large MOMENTARY per-trial part (kappa * xi,
    # xi re-drawn fresh on every call), so that high-ambiguity designs
    # show tight, chance-centered conformity rather than fixed
    # idiosyncratic deciders that spread the population apart.
    distinct = (np.unique(val).shape[0] == n_features)
    if distinct and ambiguity > 0.0:
        amb3 = ambiguity * ambiguity * ambiguity
        xi = np.random.uniform(-1.0, 1.0, size=n_features)
        w = w + amb3 * (sigma_h * zeta + kappa * xi)

    # Consult cues in DESCENDING subjective weight. np.lexsort uses the
    # LAST key as primary. Exact ties in w are broken by the free
    # per-subject tie_break parameter (population-consistent: ~80% of
    # subjects break ties by early display position).
    pos = np.arange(n_features)
    secondary = pos if tie_break < 0.8 else (n_features - 1 - pos)
    cue_order = np.lexsort((secondary, -w))

    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        if b[j] > a[j]:
            winner = 1
            break

    n_opts = 2
    if winner is None:
        # No discriminating cue: pure guess (lapse mixing leaves a
        # uniform unchanged).
        return np.ones(n_opts) / float(n_opts)

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    # Numerically stable softmax over the binary winner score: the
    # winner's probability is sigmoid(beta). Implied decider-follow
    # probability p_f = (1-eps)*sigmoid(beta) + eps/2 has mean ~0.71
    # with per-subject SD ~0.08 over the sampled (beta, epsilon) ranges.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / float(n_opts))
```

**`policy(probs)`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return np.random.choice(len(probabilities), p=probabilities)
```


### slot 2 — `pi_8` — KILLED ✗

**Description:** Anchored Anti-Validity Frugality with Validity-Respecting Leak (frozen-discipline variant). People are one-reason decision makers: experts are consulted one at a time and the first strictly discriminating expert decides; no integration across cues. The population-central hierarchy is anti-validity (distrust-the-weakest) and the population is typeless — every subject is a continuous perturbation around that core. Three graded, design-scaled mechanisms modulate the core. (1) GAP-PROPORTIONAL ANCHORING: per-trial attention noise on expert j is scaled by the local validity gaps adjacent to j in the subjective order, gated by cubed binding ambiguity, so validity-isolated experts anchor the order while dense clusters diffuse; exact validity ties anchor the order entirely. (2) VALIDITY-RESPECTING LEAK, now TRIAL-CONDITIONAL and implemented as a probability mixture: the leak toward the standard TTB (descending-validity) order fires only when the anti-validity cascade's first discriminating expert on that trial is a strictly INTERIOR validity (min_val + 0.10 < val < max_val - 0.10), with design-level probability q = min(rho_leak * reversal_coherence * mean_gap, 0.18). When the anti-decider's carrier is a weakest or near-top expert, the leak is switched off — protecting the pure anti-validity-follow designs — while genuinely mid-validity carriers let a fraction of trials flip toward the strongest discriminator, generating below-chance reversed-cascade following where the data demand it. (3) DESIGN-SCALED RESPONSE DISCIPLINE with a DISTINCT-DESIGN BONUS: p_f = (1-eps)*sigmoid(beta_eff) + eps/2 with beta_eff = beta*(1 + boost*(1-A))*(1 + b_distinct) when all validities are distinct — distinct-validity designs (which the data show want tighter decider-following) get a bounded bonus, tie designs are untouched. Response-discipline and diffusion parameters are FROZEN at narrow windows reproducing the accepted base's behavior, so only the leak strength and the distinct bonus are free.

**Rationale:** This is a surgical edit of the accepted iter-1 base implementing the iter-3 critic's prescription, whose two prior rejection diagnoses I take as ground truth: (i) the leak-gate DIRECTION was empirically right both times (Exps 3/9/10 moved correctly in isolation), but (ii) range-narrowing failed twice as a drift-control strategy because the leak changed the joint likelihood landscape and dragged the shared response-discipline parameters (beta/boost) upward, inflating p_f and regressing every decider-follow metric (Exps 4, 5, 6, 10, 7, 13). I therefore change the drift-control STRATEGY, not just the ranges. (1) FREEZE: beta, boost, epsilon, gamma, kappa, sigma_h are confined to narrow windows centered on the base's mid-range values (I verified analytically that mid-range values reproduce the base's Exp-5 follow of ~0.68 and Exp-3 anti-follow of ~0.71, i.e., the base's operating point), so only rho_leak and the new b_distinct are effectively free. (2) SYMMETRIC INTERIOR GATE (delta = 0.10 hardcoded): the leak is eligible only when the anti-validity cascade's carrier j* on this trial satisfies min + 0.10 < val[j*] < max - 0.10. Hand-traced consequences: on Exp 3 the carrier is always the 0.5-validity minimum expert -> leak provably OFF -> Exp 3 must stay at (or slightly above, via the distinct bonus) the base's value, serving as the freeze regression test; on Exp 6 the carriers are the 0.6-validity minima -> leak OFF; on Exp 7 the design's validity set {0.6, 0.65, 0.85, 0.9, 0.95} contains NO strictly interior values, so the leak never fires there — this removes iter-2's wrong-direction T11 flip while restoring the base's pure anti-follow; on Exp 9 the dissociating carriers are weak experts (<= 0.7 = min + 0.10) -> leak OFF, protecting the near-exact 0.427 fit; on Exp 8 the interior carriers (0.75, 0.8) let the leak flip toward TTB exactly where TTB opposes the reversed cascade, pushing the metric more negative as the data demand. (3) PROBABILITY MIXTURE instead of a per-trial Bernoulli for the leak (numerically equivalent, lower Monte Carlo variance), with ceiling lowered to 0.18 and rho_leak widened to [0.5, 3.0] so the cap — not an attenuated coherence x gap product — does the bounding on high-product designs (Exp 13's product is ~0.097, so the leak can reach the cap there if the fit wants it). (4) DISTINCT-DESIGN BONUS b_distinct in [0, 0.25] multiplying beta_eff when all validities are distinct: this is the orthogonal p_f knob the critic prescribed, along the axis (distinct vs tied) the data actually support — it raises follow on the distinct designs that undershoot (Exps 1, 3, 10, 15) while leaving the tie designs (Exps 5, 6, 7, 13) exactly at base behavior, preventing the cross-contamination that killed iters 2 and 3. (5) Exp 10 is the top-priority target (largest base miss, -31): the interior gate switches the leak off on its weakest-carrier agreeing cells, and the bounded distinct bonus raises the mean follow toward the real level without the uncontrolled inflation that overshot iter-3 to 150.9. I accept Exp 13 (~0.30 vs 0.15) and the Exp 7 structural cap (~-0.20 vs -0.31) as residual misses shared by every one-reason competitor, per the critic's explicit instruction not to trade the winnable experiments for them. All changes stay strictly inside the prescribed Anchored Anti-Validity Frugality with Validity-Respecting Leak family.

**Parameters:**
  - `beta`: `[0.80, 1.00]`
  - `boost`: `[0.28, 0.42]`
  - `b_distinct`: `[0.0, 0.25]`
  - `epsilon`: `[0.12, 0.16]`
  - `gamma`: `[-0.01, 0.03]`
  - `kappa`: `[7.5, 9.5]`
  - `sigma_h`: `[0.18, 0.28]`
  - `rho_leak`: `[0.5, 3.0]`
  - `zeta`: `[(-1, 1)] * n_features`
  - `tie_break`: `[0, 1]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Anchored Anti-Validity Frugality with Validity-Respecting Leak
    # (frozen-discipline variant).
    #
    # Minimal-diff edit of the accepted iter-1 base:
    #   (a) The validity-respecting leak is now TRIAL-CONDITIONAL: it is
    #       eligible only when the anti-validity cascade's first
    #       discriminating expert j* on this trial carries a strictly
    #       INTERIOR validity (min + 0.10 < val[j*] < max - 0.10), and
    #       it is implemented as a PROBABILITY MIXTURE (no Bernoulli
    #       draw) with ceiling 0.18.
    #   (b) A DISTINCT-DESIGN BONUS b_distinct multiplies beta_eff when
    #       all validities are distinct (tie designs untouched).
    #   (c) Response-discipline / diffusion parameters are FROZEN at
    #       narrow windows that reproduce the accepted base's behavior;
    #       only rho_leak and b_distinct are genuinely free.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float).ravel()
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    beta = float(parameters["beta"])
    boost = float(parameters["boost"])
    b_distinct = float(parameters["b_distinct"])
    epsilon = float(parameters["epsilon"])
    gamma = float(parameters["gamma"])
    kappa = float(parameters["kappa"])
    sigma_h = float(parameters["sigma_h"])
    rho_leak = float(parameters["rho_leak"])
    tie_break = float(parameters["tie_break"])

    zeta = np.asarray(parameters["zeta"], dtype=float).ravel()
    if zeta.shape[0] != n_features:
        raise ValueError(
            f"zeta length {zeta.shape[0]} != n_features {n_features}."
        )

    # ---- helper: average-tie ranks ----
    def avg_ranks(x):
        n = x.shape[0]
        srt = np.argsort(x, kind="stable")
        ranks = np.empty(n, dtype=float)
        i = 0
        while i < n:
            j = i
            while j + 1 < n and x[srt[j + 1]] == x[srt[i]]:
                j += 1
            ranks[srt[i:j + 1]] = 0.5 * (i + j)  # 0-indexed average rank
            i = j + 1
        return ranks

    # ---- positional-salience gradient (early-listed experts favored) ----
    if n_features > 1:
        sal = ((n_features - 1 - np.arange(n_features, dtype=float))
               / (n_features - 1.0)) - 0.5
    else:
        sal = np.zeros(1, dtype=float)

    # ---- binding ambiguity: A = 1 - |Spearman(position, validity)| ----
    if n_features > 1:
        ranks = avg_ranks(val)
        pos_r = np.arange(n_features, dtype=float)
        vp = pos_r - pos_r.mean()
        vr = ranks - ranks.mean()
        denom = np.sqrt(float((vp * vp).sum()) * float((vr * vr).sum()))
        if denom > 1e-12:
            rho = float((vp * vr).sum()) / denom
        else:
            rho = 0.0
        ambiguity = 1.0 - abs(rho)
    else:
        ambiguity = 0.0

    # ---- reversal coherence: |Spearman(validity, validity[::-1])| ----
    if n_features > 1:
        ranks_v = avg_ranks(val)
        ranks_r = avg_ranks(val[::-1])
        dv = ranks_v - ranks_v.mean()
        dr = ranks_r - ranks_r.mean()
        denom2 = np.sqrt(float((dv * dv).sum()) * float((dr * dr).sum()))
        if denom2 > 1e-12:
            rho_rev = float((dv * dr).sum()) / denom2
        else:
            rho_rev = 0.0
        coherence = abs(rho_rev)
    else:
        coherence = 0.0

    # ---- mean adjacent validity gap over UNIQUE validities ----
    uvals = np.unique(val)
    if uvals.size > 1:
        mean_gap = float(np.mean(np.diff(np.sort(uvals))))
    else:
        mean_gap = 0.0

    distinct = (uvals.size == n_features)

    # ---- gap-proportional anchoring ratios (verbatim from base) ----
    ref_gap = 0.10
    gap_ratio = np.ones(n_features, dtype=float)
    if distinct and n_features > 1:
        srt = np.argsort(val, kind="stable")
        sv = val[srt]
        gs = np.ones(n_features, dtype=float)
        for r in range(n_features):
            g = 0.0
            if r > 0:
                g += sv[r] - sv[r - 1]          # gap to next weaker
            if r < n_features - 1:
                g += sv[r + 1] - sv[r]          # gap to next stronger
            gs[srt[r]] = max(g, 0.05)           # numerical floor
        gap_ratio = np.minimum(ref_gap / gs, 2.0)

    amb3 = ambiguity * ambiguity * ambiguity

    pos = np.arange(n_features)
    secondary = pos if tie_break < 0.8 else (n_features - 1 - pos)

    a, b = stim[0], stim[1]

    def cascade_winner(order):
        for j in order:
            if a[j] > b[j]:
                return 0
            if b[j] > a[j]:
                return 1
        return None

    # ---- STABLE anti-validity weights (no momentary noise): used ONLY
    # to locate this trial's anti-validity carrier j* for the leak gate.
    w_stable = -val + gamma * sal
    if distinct and ambiguity > 0.0:
        w_stable = w_stable + amb3 * kappa * gap_ratio * sigma_h * zeta
    order_stable = np.lexsort((secondary, -w_stable))

    j_star = None
    for j in order_stable:
        if a[j] != b[j]:
            j_star = int(j)
            break

    # ---- TRIAL-CONDITIONAL leak eligibility: strictly interior carrier.
    # Weakest-expert carriers (val <= min + 0.10) and near-top carriers
    # (val >= max - 0.10) switch the leak OFF; only genuinely mid-
    # validity carriers let the TTB leak fire. Ceiling 0.18.
    leak_q = 0.0
    if j_star is not None and n_features > 1:
        vmin = float(val.min())
        vmax = float(val.max())
        if (vmin + 0.10) < val[j_star] < (vmax - 0.10):
            leak_q = float(min(rho_leak * coherence * mean_gap, 0.18))

    # ---- per-trial subjective hierarchy (momentary diffusion added) ----
    w = w_stable.copy()
    if distinct and ambiguity > 0.0:
        xi = np.random.normal(0.0, 1.0, size=n_features)
        w = w + amb3 * kappa * gap_ratio * xi
    order_anti = np.lexsort((secondary, -w))
    winner_anti = cascade_winner(order_anti)

    n_opts = 2
    if winner_anti is None:
        # No discriminating cue: pure guess (lapse mixing leaves a
        # uniform unchanged).
        return np.ones(n_opts) / float(n_opts)

    # ---- design-scaled response discipline with DISTINCT-DESIGN BONUS ----
    beta_eff = beta * (1.0 + boost * (1.0 - ambiguity))
    if distinct:
        beta_eff = beta_eff * (1.0 + b_distinct)

    def score_prob(winner):
        scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
        z = beta_eff * (scores - scores.max())
        e = np.exp(z)
        return e / e.sum()

    p_core = score_prob(winner_anti)

    # ---- VALIDITY-RESPECTING LEAK as a probability mixture (no
    # Bernoulli draw -> lower Monte Carlo variance in simulated metrics).
    if leak_q > 0.0:
        order_ttb = np.lexsort((secondary, -val))
        winner_ttb = cascade_winner(order_ttb)
        if winner_ttb is not None and winner_ttb != winner_anti:
            p_core = (1.0 - leak_q) * p_core + leak_q * score_prob(winner_ttb)

    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / float(n_opts))
```

**`policy(probs)`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return np.random.choice(len(probabilities), p=probabilities)
```


## Replacement

### `pi_9` → slot 2 (via `new_theory`)

**Description:** Diffuse Mixture Frugality with Strong Interior-Gated Validity Leak (sub-linear coherence variant). People are one-reason decision makers: experts are consulted one at a time and the first strictly discriminating expert decides; no integration across cues, no history use, exact validity ties anchor the consultation order, and a trial with no discriminating expert yields exactly 0.5. The population-central hierarchy is anti-validity (distrust-the-weakest: consult ascending advertised validity). Three graded mechanisms modulate the core. (1) STRONG INTERIOR-GATED VALIDITY LEAK with SUB-LINEAR COHERENCE WEIGHTING: when the anti cascade's first discriminating expert carries a strictly interior validity (min + 0.10 < val < max - 0.10), the decision mixes toward the standard TTB (descending-validity) decider with probability q = rho_leak * sqrt(reversal_coherence) * gap_term, where gap_term is the range-normalized mean adjacent unique-validity gap. The sub-linear coherence exponent leaves fully reversal-coherent designs (coherence ~ 1) exactly on their calibrated anchor values while granting moderately coherent designs substantially more leak mass than the linear weighting did — capturing the empirical fact that leak toward the strongest expert is not confined to perfectly mirror-structured validity lists. (2) DIFFUSE HETEROGENEITY: w_j = -val_j + gamma*salience_j + A^3*(sigma_h*zeta_j + kappa*xi_j), with a small stable per-subject part (zeta) and a large momentary per-trial part (xi), applied only when all validities are distinct. (3) POSITIONAL-PRIMACY MINORITY, TIE-ANCHORED and STEEPLY THRESHOLD-GATED: the reading-order fallback fires only on designs that BOTH contain exact advertised-validity ties AND exhibit near-maximal binding ambiguity (A >= 0.80, linear ramp over 0.20, mixture weight capped at 0.35); all-distinct and monotone/anchored designs remain fully collapsed onto the anti-validity core. Response discipline is heterogeneous: softmax(beta) plus lapse epsilon with beta in [0.3, 2.0] and epsilon in [0.08, 0.30], giving pooled decider-follow ~0.69 with the wide between-subject spread that reproduces the follow-protection tail.

**Rationale:** Minimal-diff edit of the running-best (iter-2) base following the critic's iteration-4 prescription exactly: change ONE thing whose expected effect exceeds the ~0.03 run-to-run noise floor, plus retain the one mechanism the critic explicitly confirmed. (1) THE ONE NEW KNOB — SUB-LINEAR COHERENCE WEIGHTING IN THE LEAK: q = rho_leak * coherence**0.5 * gap_term instead of rho_leak * coherence * gap_term, with rho_leak [0.85, 1.25] and the range-normalized gap_term unchanged. This is a pure normalization-scheme swap inside the arbiter's prescribed leak family. By construction it leaves the high-coherence anchors untouched (coherence ~ 1.0 on the leak-dip design Exp 17, the knife-edge designs Exps 4/1/3, so their near-perfect fits — Exp 17 at -0.198 vs -0.196 observed, Exp 10 at 118.8 vs 116.6 — are preserved), while moderately coherent designs gain leak mass toward the TTB decider: Exp 5 (coherence ~0.38 -> effective 0.62, ~+60% leak on its f4-carrier ladder cells) should pull its +0.06 over-prediction (0.672 vs 0.613 observed) down toward target; Exp 8 (coherence ~0.4-0.5) should deepen its negative misbound-decider contrast from -0.223 toward the observed -0.289; Exp 9/10 (coherence ~0.6 -> effective 0.77, ~+29%) get a small pull-down, with Exp 10's +2.3 overshoot acceptable down to ~110 per the critic's stated floor. (2) RETAINED: the steepened tie-anchored primacy gate from the (rejected) iter-3/4 candidates — threshold lowered from 0.85 to 0.80, ramp widened to /0.20, cap 0.35 — which the critic confirmed moved Exp 13 in the right direction in BOTH trial iterations (0.298 -> 0.268/0.271) without a real cost on Exp 15 (iter 3's 0.1256 with the same gate shows iter 4's 0.071 was Monte Carlo noise, not mechanism). Exp 13's design (ties, A ~ 0.91) now gets gate ~0.55 -> w_eff ~ 0.20 instead of ~0.15, pushing its value from ~0.30 toward ~0.27; the count-contrast design (all-distinct validities) keeps w_eff = 0 exactly, protecting Exp 15's recovered +0.12 contrast. (3) RESTORED VERBATIM: the base's response-discipline ranges (beta [0.3, 2.0], epsilon [0.08, 0.30]) — the discipline axis was sampled at three points in this loop (iters 2/3/4) and the base's setting is the empirical optimum; the coupled beta+epsilon moves of iters 3 and 4 were each rejected because their systematic effects were smaller than the run-to-run Monte Carlo noise on the high-ambiguity diffusion designs, so the discipline knob is renounced. (4) RENOUNCED EXPLICITLY, per the critic's structural diagnosis: Exp 7 (its validities contain nothing strictly inside the interior band (0.7, 0.85), so the leak is structurally gated off — ~-0.19 is the family bound vs -0.311 observed), Exp 6 (ties + zero binding ambiguity switch off every graded mechanism; all anti-validity-core theories over-predict it), Exp 13's residual (family floor ~0.25-0.27), and Exp 2's residual (partly noise). No fitted experiment is traded for these. The expected net effect is dominated by gains on Exps 5, 8, and 10 against at most small, monitorable costs on Exp 9 — a favorable trade under the aggregate L2 loss that should land at or below the 0.0739 floor.

**Parameters:**
  - `rho_leak`: `[0.85, 1.25]`
  - `primacy_weight`: `[0.3, 0.45]`
  - `gamma`: `[-0.05, 0.12]`
  - `sigma_h`: `[0.6, 1.2]`
  - `kappa`: `[8, 12]`
  - `beta`: `[0.3, 2.0]`
  - `epsilon`: `[0.08, 0.30]`
  - `tie_break`: `[0, 1]`
  - `zeta`: `[(-1, 1)] * n_features`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    # Diffuse Mixture Frugality with Strong Interior-Gated Validity Leak
    # (sub-linear coherence variant: sqrt(coherence) leak weighting,
    # steepened tie-anchored primacy gate at A >= 0.80).
    #
    # One-reason decision making: experts consulted one at a time, first
    # strictly discriminating expert decides; no integration across cues.
    # Population-central hierarchy: ANTI-VALIDITY (ascending advertised
    # validity; distrust the weakest expert).
    #
    # Mechanisms:
    #   (1) STRONG INTERIOR-GATED VALIDITY LEAK: when the anti cascade's
    #       first discriminating expert j* carries a strictly interior
    #       validity (min+0.10 < val[j*] < max-0.10), mix toward the TTB
    #       (descending-validity) decider with probability
    #       q = rho_leak * coherence^0.5 * gap_term,
    #       where gap_term = mean adjacent unique-validity gap NORMALIZED
    #       by the validity range (vmax - vmin). The SUB-LINEAR coherence
    #       exponent is the single change vs the accepted base: designs
    #       with coherence ~ 1.0 (the leak anchors: leak-dip, knife-edge,
    #       reversed-cascade designs) keep q unchanged (sqrt(1) = 1),
    #       while moderately coherent designs gain leak mass — e.g.
    #       coherence 0.38 -> effective 0.62 (+62%), coherence 0.6 -> 0.77
    #       (+29%) — pulling their over-predicted decider-follow contrasts
    #       down toward the observed values without touching the anchors.
    #   (2) DIFFUSE HETEROGENEITY: w_j = -val_j + gamma*salience_j
    #       + A^3*(sigma_h*zeta_j + kappa*xi_j), applied only when all
    #       validities are distinct; zeta stable per subject, xi re-drawn
    #       every trial.
    #   (3) POSITIONAL-PRIMACY MINORITY, TIE-ANCHORED + STEEP-THRESHOLD-
    #       GATED (retained from the iter-3/4 experiments, per the
    #       critic's confirmation): the reading-order fallback fires ONLY
    #       on designs that both contain exact validity ties AND have
    #       near-maximal binding ambiguity (A >= 0.80, ramp (A-0.80)/0.20),
    #       with the mixture weight capped at 0.35. All-distinct designs
    #       and monotone/anchored designs keep the pure leak-augmented
    #       anti-validity core.
    #
    # Response discipline: softmax(beta) over the binary winner score plus
    # independent lapse epsilon, with the ACCEPTED BASE's ranges verbatim
    # (beta in [0.3, 2.0], epsilon in [0.08, 0.30]) — the discipline axis
    # was sampled at three points in this loop and the base's setting is
    # the optimum; it is not touched again.
    # No discriminating cue -> exactly 0.5. History is ignored.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float).ravel()
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    gamma = float(parameters["gamma"])
    sigma_h = float(parameters["sigma_h"])
    kappa = float(parameters["kappa"])
    rho_leak = float(parameters["rho_leak"])
    primacy_weight = float(parameters["primacy_weight"])
    tie_break = float(parameters["tie_break"])

    zeta = np.asarray(parameters["zeta"], dtype=float).ravel()
    if zeta.shape[0] != n_features:
        raise ValueError(
            f"zeta length {zeta.shape[0]} != n_features {n_features}."
        )

    n_opts = 2
    a, b = stim[0], stim[1]

    if not np.any(a != b):
        # No discriminating cue: pure guess (lapse mixing leaves a
        # uniform unchanged).
        return np.ones(n_opts) / float(n_opts)

    # ---- helper: average-tie ranks ----
    def avg_ranks(x):
        n = x.shape[0]
        srt = np.argsort(x, kind="stable")
        ranks = np.empty(n, dtype=float)
        i = 0
        while i < n:
            j = i
            while j + 1 < n and x[srt[j + 1]] == x[srt[i]]:
                j += 1
            ranks[srt[i:j + 1]] = 0.5 * (i + j)  # 0-indexed average rank
            i = j + 1
        return ranks

    # ---- positional-salience gradient (early-listed experts favored) ----
    if n_features > 1:
        sal = ((n_features - 1 - np.arange(n_features, dtype=float))
               / (n_features - 1.0)) - 0.5
    else:
        sal = np.zeros(1, dtype=float)

    # ---- binding ambiguity: A = 1 - |Spearman(position, validity)| ----
    if n_features > 1:
        ranks = avg_ranks(val)
        pos_r = np.arange(n_features, dtype=float)
        vp = pos_r - pos_r.mean()
        vr = ranks - ranks.mean()
        denom = np.sqrt(float((vp * vp).sum()) * float((vr * vr).sum()))
        if denom > 1e-12:
            rho = float((vp * vr).sum()) / denom
        else:
            rho = 0.0
        ambiguity = 1.0 - abs(rho)
    else:
        ambiguity = 0.0

    # ---- reversal coherence: |Spearman(validity, validity[::-1])| ----
    if n_features > 1:
        ranks_v = avg_ranks(val)
        ranks_r = avg_ranks(val[::-1])
        dv = ranks_v - ranks_v.mean()
        dr = ranks_r - ranks_r.mean()
        denom2 = np.sqrt(float((dv * dv).sum()) * float((dr * dr).sum()))
        if denom2 > 1e-12:
            rho_rev = float((dv * dr).sum()) / denom2
        else:
            rho_rev = 0.0
        coherence = abs(rho_rev)
    else:
        coherence = 0.0

    # ---- mean adjacent gap over UNIQUE validities, RANGE-NORMALIZED ----
    # gap_term = mean_gap / (vmax - vmin): a scale-free measure of how
    # coarse the validity grid is, so coherent small-range designs are
    # no longer starved of leak mass relative to wide-range designs.
    uvals = np.unique(val)
    distinct = (uvals.size == n_features)
    has_ties = (uvals.size < n_features)
    if uvals.size > 1:
        mean_gap = float(np.mean(np.diff(uvals)))
        v_range = float(uvals[-1] - uvals[0])
        gap_term = mean_gap / v_range if v_range > 1e-12 else 0.0
    else:
        gap_term = 0.0

    pos = np.arange(n_features)
    secondary = pos if tie_break < 0.8 else (n_features - 1 - pos)

    # ---- anti-validity weights with diffuse heterogeneity ----
    # Exact validity ties anchor the distrust order (no distortion);
    # all-distinct lists degrade with the CUBE of binding ambiguity.
    # Small stable part (sigma_h * zeta) + large momentary part
    # (kappa * xi, re-drawn fresh on every trial).
    w = -val + gamma * sal
    if distinct and ambiguity > 0.0:
        amb3 = ambiguity * ambiguity * ambiguity
        xi = np.random.uniform(-1.0, 1.0, size=n_features)
        w = w + amb3 * (sigma_h * zeta + kappa * xi)
    order_anti = np.lexsort((secondary, -w))

    def cascade(order):
        for j in order:
            if a[j] > b[j]:
                return 0
            if b[j] > a[j]:
                return 1
        return None

    winner_anti = cascade(order_anti)

    # ---- this trial's anti-validity carrier (for the leak gate) ----
    j_star = None
    for j in order_anti:
        if a[j] != b[j]:
            j_star = int(j)
            break

    def score_prob(winner):
        scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
        z = beta * (scores - scores.max())
        e = np.exp(z)
        return e / e.sum()

    # Start from the (momentary) anti-validity decider.
    p = score_prob(winner_anti)

    # ---- POSITIONAL-PRIMACY MINORITY (tie-anchored, steep-threshold gate) ----
    # The reading-order fallback is elicited ONLY when the design BOTH
    # contains exact advertised-validity ties AND sits in the near-maximal
    # binding-ambiguity regime (A >= 0.80, linear ramp over 0.20). This is
    # the steepened gate confirmed by the critic: it lowered the
    # anti-misbound-decider follow (Exp 13) in both trial iterations
    # without a real cost on the count-vs-primacy contrast (Exp 15),
    # whose all-distinct validities keep w_eff = 0 exactly.
    if has_ties and ambiguity >= 0.80:
        gate = min(1.0, max(0.0, (ambiguity - 0.80) / 0.20))
    else:
        gate = 0.0
    w_eff = min(primacy_weight * gate, 0.35)
    if w_eff > 0.0:
        winner_prim = cascade(pos)  # earliest-listed expert first
        if winner_prim is not None:
            p = (1.0 - w_eff) * p + w_eff * score_prob(winner_prim)

    # ---- STRONG INTERIOR-GATED VALIDITY LEAK ----
    # Fires only when the anti cascade's carrier is strictly interior:
    # min + 0.10 < val[j*] < max - 0.10. Weakest-carrier and near-top
    # carrier trials keep the leak OFF.
    # SINGLE CHANGE vs the accepted base: the coherence factor enters
    # SUB-LINARLY (coherence**0.5) instead of linearly. High-coherence
    # anchor designs are untouched by construction (sqrt(1) = 1);
    # moderately coherent designs gain leak mass, pulling their
    # over-predicted decider-follow contrasts toward the observed values.
    if j_star is not None and n_features > 1:
        vmin = float(val.min())
        vmax = float(val.max())
        if (vmin + 0.10) < val[j_star] < (vmax - 0.10):
            q = rho_leak * (coherence ** 0.5) * gap_term
            # Numerical validity clamp only (keeps mixture weights proper
            # probabilities on extreme small-n designs); far above the
            # substantive target range on the leak-dip design.
            q = min(max(q, 0.0), 0.75)
            if q > 0.0:
                order_ttb = np.lexsort((secondary, -val))
                winner_ttb = cascade(order_ttb)
                if winner_ttb is not None:
                    p = (1.0 - q) * p + q * score_prob(winner_ttb)

    # ---- heterogeneous response discipline: softmax + lapse ----
    # (base ranges verbatim: beta [0.3, 2.0], epsilon [0.08, 0.30])
    return (1.0 - epsilon) * p + epsilon * (np.ones(n_opts) / float(n_opts))
```

**`policy(probs)`:**
```python
def policy(probs):
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # guard against float drift
    return np.random.choice(len(probabilities), p=probabilities)
```
