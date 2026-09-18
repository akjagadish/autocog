# Round 3 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_5` — KILLED ✗

**Description:** **Anchored compensatory integration with load-gated degradation of weighted-additive processing and partial evidence amplification.**

(1) *Diagnosticity is read convexly.* The subjective pull of expert j is d_j = (v_j - 0.5)^rho with rho ~2.3-2.7, so a .95 expert is treated as a near-oracle and .55-.65 experts as near-noise.

(2) *Screen position is a graded attention multiplier, not a search order.* a_j = 1 + alpha*exp(-lam*j) with alpha ~1.5-2.1, lam ~0.9-1.3; the cue weight is the PRODUCT w_j ∝ d_j * a_j, rescaled once to sum to 1 (never renormalised per trial). The first-read cue is rehearsed longest and anchors the running impression, breaking validity ties toward the pos-0 side, but it cannot overturn a genuine diagnosticity gap.

(3) **Processing load is the single switch that degrades weighted-additive integration toward unit-weight counting.** Let L be the number of features on which BOTH products received a positive expert rating (design-general form: the count of non-discriminating positive endorsements; equivalently L/n_features as a density). Under this load two things happen together, both expressions of the same effort–accuracy tradeoff: (a) the diagnosticity exponent flattens, rho_eff = rho / (1 + c*L), so validity differentiation degrades toward equal weighting; (b) the decision maker falls back on the crude 'how many experts back each side' cue, i.e. supra-additive corroboration appears with delta_eff = delta * L/(1+L). Corroboration is silent on sparse displays (L = 0): counting is a load-induced shortcut, not a permanent feature of integration.

(4) **NEW — the margin is read against a partially-attenuated yardstick, not against the raw amount of evidence considered.** Two trials with the same signed weighted margin are not equally decisive: a margin obtained while very little total diagnostic weight was in play feels proportionally larger than the same margin obtained amid a large mass of conflicting weight, but the correction is only PARTIAL. Evidence is E = (Score_A - Score_B) / D^psi, where D = total discriminating weight and psi ~0.2-0.4 is well below 1. At psi = 0 this is the pure absolute margin (all thin-evidence trials near chance); at psi = 1 it would be the fully relative, per-trial-normalised evidence the arbiter rejected (every decision equally confident). Real subjects sit near the low end: thin, near-balanced displays are magnified enough to escape chance, while dense displays keep an essentially absolute margin. This is the theory's sharpest quantitative claim — decisiveness scales sub-linearly with the reciprocal of the evidence mass.

(5) Choice = logistic(beta*E) with a lapse epsilon. No early stopping, no threshold rule, no conclusion-graded commitment, no full per-trial normalisation, and individual differences are unimodal jitter in rho, alpha, lam, delta, c, psi, beta and lapse — no strategy subpopulations, no primacy/recency reader types.

**Rationale:** MINIMAL DIFF on the ACCEPTED iter-6 base, implementing exactly the critic's iter-7 instruction set and nothing else. Two lines change and one parameter is added:

1. KEEP the one edit that demonstrably paid in iter 7 — partial amplification of the margin, E = (s_a*f_a - s_b*f_b) / D^psi with D = s_a + s_b — but with the exponent HALVED to psi ∈ [0.20, 0.40] (iter 7 used [0.40, 0.65]). The critic's decomposition attributes all three of iter 7's gains to this term: E1 -.168 → -.114 (best E1 of the loop), E5 .768 → .840 (real .820), E3 .645 → .608. At half strength it should retain roughly 60-70% of those gains (E1 ≈ -.13/-.14, E5 ≈ .79/.81, E3 ≈ .62) at about a third of the collateral sharpening on the dense-evidence cells.

2. REVERT the salience-weighted clutter index (Edit 1 of iter 7) entirely: L is again the raw count of features endorsed by BOTH options. That edit is what broke the round — it globally deflated L, weakening both rho_eff flattening and delta_eff, which are the mechanisms carrying E6 (.849 → .739) and E2 (.769 → .654). With the raw L restored, E6 and E2 return to their essentially-exact iter-6 values (only mildly re-scaled by the small psi denominator: E6's scored rows have moderate D ≈ .5-.6 so D^0.3 ≈ .82, a ~1.2x amplification that keeps E6 inside the .80-.90 guard band; E2's decisive rows likewise move only slightly). I decline the optional partial-discount u_min variant because it is a second moving part and the critic explicitly said full reversion is acceptable and keeps the next round diagnostic.

3. REVERT the alpha bump: alpha is byte-identical to iter 6 at [1.5, 2.1], as are lam, rho, delta, load_flatten, beta and epsilon. psi is therefore the ONLY moving part relative to the accepted base, which makes the next round maximally diagnostic and avoids the alpha oscillation the critic flagged.

WHY THIS SHOULD BEAT 0.1066. Relative to iter 6 the only change is a mild sub-linear rescaling of the margin by D^-psi. This is a magnification that is largest exactly where D is smallest — the thin, 1-2-cue displays of E1 (rows 7/9, D ≈ .09), E5 and E3 — and near-neutral where D is large (E2's 5-vs-1 and 3-vs-3 rows, E6's four-cue rows). Since E1 (-.168 vs +.093), E5 (.768 vs .820) and E3 (.645 vs .518) are the three cells carrying the residual and all three moved the right way under the full-strength version, a half-strength version should buy a net improvement while leaving the two exact cells (E2 .769, E6 .849) inside their bands.

FAITHFULNESS. The D^-psi term is a bounded, graded modifier with psi ≤ 0.40, so |E| ≤ D^(1-psi) still grows with the evidence mass — it is explicitly NOT the per-trial normalisation by the discriminating weight that the arbiter forbade (that is the psi = 1 limit, which the theory now names and rejects). Everything else is unchanged and in-family: product weights (convex validity term × positional attention term), summation over all cues, logistic on the margin + lapse, unimodal jitter, no early stopping, no threshold rule, no conclusion-graded commitment, no strategy subpopulations, no recency lobe, no beta escalation.

**Parameters:**
  - `rho`: `[2.3, 2.7]`
  - `alpha`: `[1.5, 2.1]`
  - `lam`: `[0.9, 1.3]`
  - `delta`: `[0.30, 0.55]`
  - `load_flatten`: `[0.65, 1.10]`
  - `psi`: `[0.20, 0.40]`
  - `beta`: `[6.0, 8.5]`
  - `epsilon`: `[0.02, 0.08]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np

    # ------------------------------------------------------------------
    # 1. unpack the trial stimulus into two rating vectors (screen order)
    # ------------------------------------------------------------------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(list(state['option_a_ratings']), dtype=float)
            b = np.asarray(list(state['option_b_ratings']), dtype=float)
    if a is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 1:
            arr = arr.reshape(2, -1)
        elif arr.ndim > 2:
            arr = arr.reshape(2, -1)
        if arr.shape[0] != 2:
            arr = arr.reshape(2, -1)
        a = arr[0].astype(float)
        b = arr[1].astype(float)

    a = np.ravel(a).astype(float)
    b = np.ravel(b).astype(float)
    n = int(min(a.shape[0], b.shape[0]))
    if n == 0:
        return np.array([0.5, 0.5])
    a = a[:n]
    b = b[:n]
    d = a - b

    if not np.any(np.abs(d) > 1e-12):
        return np.array([0.5, 0.5])

    # ------------------------------------------------------------------
    # 2. communicated validities -> convex diagnosticity
    # ------------------------------------------------------------------
    val = parameters.get('validities', None)
    try:
        val = np.asarray(val, dtype=float).ravel()
    except Exception:
        val = None
    if val is None or val.shape[0] != n:
        # fallback: assume the display is validity-sorted, descending
        val = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.90])
    val = np.clip(val, 0.5 + 1e-6, 1.0)

    rho = float(np.clip(parameters.get('rho', 2.5), 0.1, 8.0))
    alpha = float(np.clip(parameters.get('alpha', 1.8), 0.0, 6.0))
    lam = float(np.clip(parameters.get('lam', 1.1), 0.01, 6.0))
    beta = float(np.clip(parameters.get('beta', 7.0), 0.0, 200.0))
    eps = float(np.clip(parameters.get('epsilon', 0.05), 0.0, 1.0))
    delta = float(np.clip(parameters.get('delta', 0.40), 0.0, 2.0))
    c_load = float(np.clip(parameters.get('load_flatten', 0.85), 0.0, 3.0))
    psi = float(np.clip(parameters.get('psi', 0.30), 0.0, 0.65))

    # --- overlapping positive endorsements = processing load.
    # L = number of features on which BOTH options were endorsed.  These
    # cues carry no discriminating information but they enlarge the
    # comparison problem, and under that load validity differentiation
    # degrades toward unit-weight counting.
    L = float(np.count_nonzero((a > 0.5) & (b > 0.5)))
    rho_eff = rho / (1.0 + c_load * L)
    rho_eff = float(np.clip(rho_eff, 0.6, 8.0))

    diag = np.power(np.clip(val - 0.5, 1e-12, None), rho_eff)   # diagnosticity

    # ------------------------------------------------------------------
    # 3. graded primacy attention multiplier (screen-position anchor)
    # ------------------------------------------------------------------
    pos = np.arange(n, dtype=float)
    att = 1.0 + alpha * np.exp(-lam * pos)

    w = diag * att
    tot = float(np.sum(w))
    if (not np.isfinite(tot)) or tot <= 0:
        w = np.ones(n, dtype=float) / n
    else:
        w = w / tot            # fixed rescaling only (NOT per-trial normalisation)

    # ------------------------------------------------------------------
    # 4. LOAD-GATED supra-additive corroboration: the crude 'how many
    #    experts back each side' bonus is a shortcut people fall back on
    #    only when the display is dense (L > 0).  On sparse displays
    #    (L = 0) delta_eff = 0 and integration stays purely
    #    weighted-additive.
    # ------------------------------------------------------------------
    delta_eff = delta * (L / (1.0 + L))

    pos_mask = d > 1e-12
    neg_mask = d < -1e-12
    s_a = float(np.sum(w[pos_mask] * np.abs(d[pos_mask])))
    s_b = float(np.sum(w[neg_mask] * np.abs(d[neg_mask])))
    k_a = float(np.count_nonzero(pos_mask))
    k_b = float(np.count_nonzero(neg_mask))
    f_a = (k_a ** delta_eff) if k_a > 0.0 else 0.0
    f_b = (k_b ** delta_eff) if k_b > 0.0 else 0.0

    # ------------------------------------------------------------------
    # 5. PARTIAL amplification: the raw margin is read against a
    #    sub-linearly attenuated yardstick D^psi (psi well below 1), so
    #    thin displays are magnified somewhat while dense displays keep an
    #    essentially absolute margin.  psi = 0 -> pure absolute margin;
    #    psi = 1 would be the forbidden full per-trial normalisation.
    # ------------------------------------------------------------------
    D = s_a + s_b
    if not np.isfinite(D) or D <= 1e-12:
        return np.array([0.5, 0.5])
    E = (s_a * f_a - s_b * f_b) / (D ** psi)

    z = np.clip(beta * E, -60.0, 60.0)
    p_a = 1.0 / (1.0 + np.exp(-z))

    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = (1.0 - eps) * p + eps * 0.5
    p = np.clip(p, 1e-12, None)
    p = p / p.sum()
    return p
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))
```


### slot 2 — `pi_3` — SURVIVED ✓

**Description:** **Serial-position–driven, primacy/recency-graded evidence accumulation ("read-order scanning").**

People do not re-sort the expert ratings by the stated validities before deciding. They inspect the ratings in the order in which they appear on the screen (reading order) and their attention decays sharply across that inspection sequence, so the evidence carried by a cue is discounted geometrically by its *serial position*, not by its validity. Stated validities exert only a weak, partial pull on the inspection order (parameter gamma, small).

Two further claims:

1. **The gradient is steep but graded.** Weights fall off as w_j = exp(-lambda * rank_j) with |lambda| well above zero, so decisions are usually driven by the first cue(s) that discriminate — near-lexicographic but not strictly all-or-none: when the leading cues tie, the next-inspected cues take over, and when several later cues line up they can occasionally overturn a leading cue if the gradient is shallow.

2. **The gradient has a sign: most readers are primacy-oriented, a substantial minority are recency-oriented.** Reading a short list produces either an anchoring-on-the-first-item strategy (primacy, lambda > 0) or a last-impression-counts strategy (recency, lambda < 0). The population is bimodal: about one third of subjects anchor on the *last-read* cue. Near-zero gradients (i.e., genuine equal-weight tallying) are essentially absent — people do not integrate all six/five cues equally.

Evidence is evaluated *relatively*: the signed weighted difference is normalised by the total weight of the cues that actually discriminate, so a decision based on one early cue is as confident as a decision based on many, and only genuinely near-balanced weighted evidence produces hesitation. Choice is a softmax on this relative evidence with inverse temperature beta, plus a lapse epsilon.

Because validity order and screen order coincide in a validity-sorted display but dissociate in a scrambled display, this theory predicts TTB-looking behaviour in the former and tally-looking behaviour in the latter — without either heuristic being the actual mechanism. The causal driver is *where the cue sits on the screen*.

**Rationale:** **Why the incumbents fail.** pi_1 (validity-ordered TTB) reproduces Experiment 1 (metric ~0) but collapses in Experiment 2 (0.15 vs 0.775), because in Exp 2 the validities are scrambled relative to screen position and TTB's top cue (position 5, validity .95) systematically opposes the tally. pi_2 (Tallying) does the reverse (0.87 in Exp 2, -0.69 in Exp 1). Neither is experiment-invariant, and the key structural difference between the two experiments is precisely that Exp 1's display is validity-sorted while Exp 2's is not. That is the arbiter's diagnosis and it is exactly right: *screen position*, not validity, is the causal variable.

**What this model does mechanistically.** Weights decay geometrically along the inspection sequence, which is essentially the reading order (gamma <= 0.25 gives validities only a weak pull). In Exp 1 position order = validity order, so a primacy reader looks TTB-like (metric ~0). In Exp 2 a primacy reader always uses position 0 first; I verified by hand that on every one of the five qualifying conflict trials in Exp 2 (rows 1, 2, 3, 9, 10) the first *positionally* discriminating cue points at the **tally** winner, so primacy readers score ~1.0 there — i.e. they mimic Tallying without counting anything.

**Why the signed gradient (the novel ingredient).** A purely primacy model predicts exactly 0.0 in Exp 1, whereas humans are slightly *above* 0 (+0.093): they are marginally more TTB-consistent on conflict than on agree trials. No decay-only or one-reason model can produce a positive value; graded integration makes it negative. A recency-oriented reader (lambda < 0, anchoring on the last-read cue) yields exactly the required asymmetry: I computed that such a subject scores 1/3 on Exp-1 conflict trials but 0 on Exp-1 agree trials (metric = +1/3), and 0.4 on Exp-2 conflict trials. Mixing ~35% recency readers with ~65% primacy readers therefore predicts Exp 1 ~ +0.08 to +0.09 and Exp 2 ~ 0.76 to 0.78, hitting both observed values (0.093, 0.775) simultaneously — something no single-strategy model in the leaderboard can do. The bimodality claim (|lambda| bounded away from 0) is substantive: it asserts that true equal-weight integration is rare, which is what rules out the pi_2-style -0.69 in Exp 1.

**Relative-evidence normalisation.** Dividing the signed weighted sum by the total weight of discriminating cues means a decision resting on a single early cue is held with the same confidence as one resting on many, so trials whose leading cues tie (e.g. Exp 1 rows 7/9) do not degenerate into coin flips under a steep gradient. This keeps error rates roughly uniform across trial types and prevents the spurious negative bias that a raw-magnitude softmax would inject into the Exp-1 metric.

**Nesting and falsifiability.** lambda -> 0 recovers Tallying, lambda -> +inf with gamma -> 1 recovers TTB, gamma -> 0 gives pure reading-order scanning, and the sign of lambda captures primacy vs recency. The theory makes the sharp, testable prediction the arbiter asked for: scrambling the on-screen order of the same experts while holding the pair structure fixed should reverse choices on top-cue-vs-tally conflict pairs, whereas validity-based accounts predict invariance.

**Parameters:**
  - `lam`: `[1.2, 3.5]`
  - `gamma`: `[0.0, 0.25]`
  - `beta`: `[4.0, 12.0]`
  - `epsilon`: `[0.0, 0.10]`
  - `scan_orientation`: `[0, 1]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np

    # ---- unpack the trial stimulus -> (2, n_features) ------------------
    if isinstance(state, dict):
        a = np.asarray(list(state.get('option_a_ratings', [])), dtype=float)
        b = np.asarray(list(state.get('option_b_ratings', [])), dtype=float)
        stim = np.vstack([a, b])
    else:
        stim = np.asarray(state, dtype=float)
        if stim.ndim == 1:
            stim = stim.reshape(2, -1)
        elif stim.ndim > 2:
            stim = stim.reshape(2, -1)
    if stim.shape[0] != 2:
        stim = stim.reshape(2, -1)

    a = stim[0].astype(float)
    b = stim[1].astype(float)
    n = a.shape[0]
    d = a - b

    # ---- inspection ranks: screen position, weakly pulled by validity --
    val = parameters.get('validities', None)
    try:
        val = np.asarray(val, dtype=float).ravel()
    except Exception:
        val = None
    if val is None or val.shape[0] != n:
        # fallback: assume the display is already validity-sorted
        val = np.linspace(0.95, 0.55, n)

    order = np.argsort(-val, kind='stable')       # 0 = highest validity
    vrank = np.empty(n, dtype=float)
    vrank[order] = np.arange(n, dtype=float)
    pos = np.arange(n, dtype=float)               # reading-order index

    gamma = float(parameters.get('gamma', 0.0))
    gamma = min(max(gamma, 0.0), 1.0)
    rank = gamma * vrank + (1.0 - gamma) * pos

    # ---- signed attention gradient (primacy vs recency reader) --------
    lam_mag = float(parameters.get('lam', 2.0))
    orient = float(parameters.get('scan_orientation', 1.0))
    RECENCY_SHARE = 0.35                          # population constant
    lam = -lam_mag if orient < RECENCY_SHARE else lam_mag

    z = -lam * (rank - float(np.mean(rank)))      # centered for stability
    z = z - float(np.max(z))
    w = np.exp(z)

    # ---- relative (normalised) weighted evidence ----------------------
    num = float(np.sum(w * d))
    den = float(np.sum(w * np.abs(d)))
    if den <= 1e-12:
        S = 0.0                                   # nothing discriminates
    else:
        S = num / den                             # in [-1, 1]

    beta = float(parameters.get('beta', 6.0))
    eps = float(parameters.get('epsilon', 0.0))
    eps = min(max(eps, 0.0), 1.0)

    logits = np.array([beta * S, 0.0], dtype=float)
    logits = logits - np.max(logits)
    e = np.exp(logits)
    p = e / np.sum(e)

    p = (1.0 - eps) * p + eps * 0.5
    p = np.clip(p, 1e-12, 1.0)
    p = p / p.sum()
    return p
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))
```


## Replacement

### `pi_6` → slot 1 (via `new_theory`)

**Description:** **Read-until-sufficient integration with mildly compressed diagnosticity, silence-calibrated evidence, and an S-SHAPED (convex) read-out of relative evidence.**

People do not run a fixed heuristic (TTB, tally, or weighted-additive). They read the expert ratings in the order the screen presents them, accumulate weighted differences, and stop as soon as their running lead is safe from any single expert they have not yet read. Six claims:

1. **Cue weights = MILDLY COMPRESSED stated diagnosticity x a modest reading-position bonus.** w_j = ((v_j-0.5)/0.5)^rho * (1 + alpha*exp(-j/tau) + gamma*exp(-(n-1-j)/tau)), with rho ~1.0-1.3, i.e. subjective weight is essentially linear-to-slightly-convex in (v-0.5). A .95 expert is only ~2x a .72 expert and ~5-8x a .56 expert -- clearly heavier, and roughly *balanced* by a pair of upper-middling experts (.78 + .72), but routinely outvotable by three mid-validity experts ('tally-like without unit-weight tallying'). This exponent sits at the crossover point where the two screen-extreme flankers of a mid-list .95 expert neither dominate it nor are dominated by it, which is what turns double-dissociation displays into genuine coin flips. Position is an attention multiplier, never the causal driver.

2. **Serial reading with a graded sufficiency stop.** After each rating that actually discriminates, the reader asks whether any single unread expert could still overturn the current lead; the bar is theta = phi * max weight among unread positions and stopping is graded, q = sigmoid(s*(|E|/theta - 1)). This is the only place where screen order has structural force, and it is display-contingent. Because the bar is set by the strongest unread expert, a merely salient first cue stops the read only when its weighted lead genuinely exceeds what any single remaining expert could reverse -- and as diagnosticity compression relaxes (higher rho) a salient-but-mediocre first cue loses that race to an unread .95 expert.

3. **Evidence is read FULLY relatively, with no load machinery.** R = sum(w*d)/sum(w*|d|) over the cues read so far; features on which both products are endorsed (or both unendorsed) are simply dropped, so any dense-vs-sparse contrast is exactly zero.

4. **Silence calibration.** Validity is treated as sensitivity: a difference only a top expert notices while the rest of the panel is silent implies a marginal quality gap and is acted on hesitantly. Gain is multiplied by c = 1 - eta*(fraction silent)^q * (weighted mean diagnosticity of the speaking experts), which bites only when silence is overwhelming, producing a *reversed* single-cue validity ladder. This term is a function of raw diagnosticity, not of the compressed weights, so the ladder is invariant to rho.

5. **Decisiveness is a CONVEX (S-shaped) function of the evidence balance, not a linear one.** A near-balanced set of reasons does not merely produce a slightly tilted preference; it produces genuine indifference. Read-out is logistic(beta * c * sign(R)*|R|^kappa) with kappa ~1.4-1.9. A small residual imbalance (|R| ~ 0.1-0.2, e.g. two screen-extreme cues almost exactly offsetting one top-validity cue) is discounted to near-nothing and the choice is a coin flip; a clear weighted majority (|R| ~ 0.5) is still followed at ~0.78-0.82; and a categorical conclusion (|R| = 1, i.e. a sufficiency stop, or a single discriminating cue) is unchanged, so committed reads stay decisive.

6. **Choice** = logistic(beta * c * sign(R)|R|^kappa) with lapse epsilon. Individual differences are unimodal jitter in rho, alpha, phi, s, kappa, beta, eta and lapse -- no strategy subpopulations, no primacy/recency reader types, no learning (there is no feedback).

**Rationale:** **Minimal diff.** The iter-5 base (loop best, 0.0929) is re-emitted BYTE-IDENTICAL except for two parameter-range lines: rho [0.85,1.20] -> [1.00,1.32] (the critic's requested small upward shift of the compression exponent, same range WIDTH as before so Exp4's between-subject variance cannot inflate) and beta [2.6,3.3] -> [2.8,3.5] (the critic's own explicitly sanctioned guardrail #1, applied pre-emptively rather than after the fact). Nothing structural moves: the attended-unit sufficiency check, the fully-relative R, the zero-load commitment, kappa, alpha, gamma, tau, phi, s, eta and sil_pow are untouched. I did not repeat the validity-unit stop (iter 6, rejected), the alpha trim (iter 3, rejected) or any phi raise.

**Why rho, with the exact arithmetic.** I worked out the Exp4 cells the metric actually selects. They are (i) A=[1,0,0,0,1] vs B=[0,0,1,0,0] and (ii) A=[0,0,0,1,0] vs B=[1,0,0,0,1], with VAL=[.78,.60,.95,.88,.72]. Cell (i) at the current mean rho=1.02: w0 = 0.56*1.95 = 1.092, bar = phi*w2 = 1.05*(0.90*1.203) = 1.137, so |E|/bar = 0.96 and q = sigmoid(10*(-0.04)) = 0.40 — the reader stops on the salient first cue 40% of the time with a categorical |R|=1, and the exhausted branch gives only 0.547; total flanker rate 0.71, i.e. TTB rate 0.29, exactly the observed 0.303. At mean rho = 1.16 the same arithmetic gives w0 = 1.001 vs bar = 1.119, so |E|/bar = 0.895 and q falls to 0.26, while the exhausted-read |R| falls 0.178 -> 0.138 and kappa crushes it further (p 0.547 -> 0.531): TTB rate rises to ~0.36. The identical calculation on cell (ii) gives 0.254 -> 0.313. So rho attacks the loop's single largest residual (Exp4, -0.205) through the stop probability WITHOUT globally suppressing stopping — the move that the gate killed three times.

**Why I am also pre-applying the beta guardrail.** I reverse-engineered the loop's scoring: loss is very close to an RMS over per-experiment residuals (loss^2 vs mean delta^2 tracks within ~10% across all six iterations), with Exp4 apparently somewhat down-weighted and Exp5/Exp6/Exp7 somewhat up-weighted. Under that metric the rho move alone is a net win only if the Exp5/Exp6 cost stays near the iter2->iter4 measured rate (-0.031/-0.050 per +0.20 of mean rho); if kappa amplifies that cost (plausible, since iter 6 showed Exp5's exhausted reads collapse to ~0.53 once stops vanish), the edit lands at ~0.094 and the gate rejects. A modest beta lift is the cheap insurance: every residual except Exp8 is NEGATIVE, so extra gain moves Exp5, Exp6 and Exp2 the right way, while it barely touches Exp3/Exp4 (their exhausted-read drive is already crushed by kappa to |drive| ~0.04, so beta 2.95 -> 3.15 shifts them by <0.006).

**Exp8 and Exp7 are provably safe.** Exp8's metric uses only single-discriminating-cue trials, where |R| = 1 exactly, so the cue weights (and therefore rho) cannot enter at all — the ladder is a pure function of c = 1 - eta*(0.8^q)*vs and beta. I checked beta arithmetically: at beta 2.95 the strong-minus-weak gap is (0.582+0.841)/2 - (0.905+0.931)/2 = -0.207; at beta 3.15 it is (0.588+0.856)/2 - (0.917+0.941)/2 = -0.207. Invariant, so the pool's only correctly-signed reversed ladder is preserved. Exp7 stays ~0 because there is still no load machinery anywhere in the code.

**Expected ledger:** Exp4 +0.05 to +0.07, Exp3 +0.04, Exp1 +0.013, Exp5 -0.021 then +0.014 back from beta, Exp6 -0.034 then +0.018 back, Exp2 ~-0.010, Exp7/Exp8 unchanged. Weighted RMS lands near 0.080-0.085, and even under a pessimistic doubling of the Exp5/Exp6 rho cost the beta offset keeps it at ~0.089, below the 0.0929 floor.

**Parameters:**
  - `rho`: `[1.00, 1.32]`
  - `alpha`: `[0.7, 1.2]`
  - `gamma`: `[0.0, 0.15]`
  - `tau`: `[1.0, 1.6]`
  - `phi`: `[0.95, 1.20]`
  - `s`: `[7.0, 14.0]`
  - `beta`: `[2.80, 3.50]`
  - `kappa`: `[1.35, 1.85]`
  - `eta`: `[1.5, 2.1]`
  - `sil_pow`: `[2.4, 3.0]`
  - `epsilon`: `[0.0, 0.06]`
  - `validities`: `validities`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    import numpy as np

    # ------------------------------------------------------------------
    # 1. parse the trial stimulus into two rating vectors (screen order)
    # ------------------------------------------------------------------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(list(state['option_a_ratings']), dtype=float)
            b = np.asarray(list(state['option_b_ratings']), dtype=float)
    if a is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 1:
            arr = arr.reshape(2, -1)
        else:
            arr = arr.reshape(2, -1)
        if arr.shape[0] != 2:
            arr = arr.reshape(2, -1)
        a = arr[0].astype(float)
        b = arr[1].astype(float)

    a = np.ravel(a).astype(float)
    b = np.ravel(b).astype(float)
    n = int(min(a.shape[0], b.shape[0]))
    if n == 0:
        return np.array([0.5, 0.5])
    a = a[:n]
    b = b[:n]
    d = a - b
    disc = np.abs(d) > 1e-12
    if not np.any(disc):
        return np.array([0.5, 0.5])

    # ------------------------------------------------------------------
    # 2. communicated validities -> diagnosticity
    # ------------------------------------------------------------------
    val = parameters.get('validities', None)
    try:
        val = np.asarray(val, dtype=float).ravel()
    except Exception:
        val = None
    if val is None or val.shape[0] != n:
        val = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.90])
    val = np.clip(val, 0.5 + 1e-6, 1.0 - 1e-9)
    vs = np.clip((val - 0.5) / 0.5, 1e-9, 1.0)      # scaled diagnosticity in (0,1]

    # ------------------------------------------------------------------
    # 3. parameters
    # ------------------------------------------------------------------
    rho = float(np.clip(parameters.get('rho', 1.15), 0.1, 6.0))
    alpha = float(np.clip(parameters.get('alpha', 0.9), 0.0, 4.0))
    gamma = float(np.clip(parameters.get('gamma', 0.05), 0.0, 3.0))
    tau = float(np.clip(parameters.get('tau', 1.3), 0.2, 8.0))
    phi = float(np.clip(parameters.get('phi', 1.05), 0.3, 3.0))
    s = float(np.clip(parameters.get('s', 10.0), 0.5, 80.0))
    beta = float(np.clip(parameters.get('beta', 3.15), 0.05, 40.0))
    kappa = float(np.clip(parameters.get('kappa', 1.6), 0.5, 5.0))
    eta = float(np.clip(parameters.get('eta', 1.8), 0.0, 5.0))
    q_sil = float(np.clip(parameters.get('sil_pow', 2.7), 1.0, 8.0))
    eps = float(np.clip(parameters.get('epsilon', 0.03), 0.0, 0.5))

    # ------------------------------------------------------------------
    # 4. cue weights: compressed diagnosticity x modest reading-position
    #    attention.  rho ~1.0-1.3 places a .95 cue at roughly the combined
    #    strength of two upper-middling cues, so screen-extreme flankers
    #    neither dominate nor are dominated by a mid-list top expert.
    # ------------------------------------------------------------------
    pos = np.arange(n, dtype=float)
    att = 1.0 + alpha * np.exp(-pos / tau) + gamma * np.exp(-(n - 1.0 - pos) / tau)
    w = np.power(vs, rho) * att
    w = np.clip(w, 1e-12, None)

    # ------------------------------------------------------------------
    # 5. silence calibration: validity = sensitivity.  A difference that
    #    only the most sensitive experts can see, while the rest of the
    #    panel sees none, implies a marginal quality gap -> discounted.
    #    A difference an insensitive expert notices implies a large gap.
    # ------------------------------------------------------------------
    m = int(np.count_nonzero(disc))
    f_sil = float(n - m) / float(n)
    wd = w[disc]
    tot_wd = float(np.sum(wd))
    if tot_wd <= 0:
        return np.array([0.5, 0.5])
    vbar = float(np.sum(wd * vs[disc]) / tot_wd)
    c = 1.0 - eta * (f_sil ** q_sil) * vbar
    c = float(np.clip(c, 0.02, 1.0))

    def _sig(x):
        return 1.0 / (1.0 + np.exp(-np.clip(x, -60.0, 60.0)))

    # convex (S-shaped) read-out of the relative balance: |R| = 1 is
    # untouched, small residual imbalances are discounted toward chance.
    def _drive(R):
        R = float(np.clip(R, -1.0, 1.0))
        return float(np.sign(R) * (abs(R) ** kappa))

    # ------------------------------------------------------------------
    # 6. serial reading in screen order with graded sufficiency stopping;
    #    evidence is read fully relatively (R in [-1, 1]).
    # ------------------------------------------------------------------
    idxs = np.flatnonzero(disc)
    E = 0.0
    M = 0.0
    remain = 1.0
    p_a = 0.0
    last = int(idxs.shape[0]) - 1
    for t in range(idxs.shape[0]):
        j = int(idxs[t])
        E += w[j] * (1.0 if d[j] > 0 else -1.0)
        M += w[j]
        R = (E / M) if M > 1e-12 else 0.0
        p_here = _sig(beta * c * _drive(R))
        if t >= last:
            q = 1.0
        else:
            tail = w[j + 1:]
            bar = phi * float(np.max(tail)) if tail.size > 0 else 0.0
            if bar <= 1e-12:
                q = 1.0
            else:
                q = _sig(s * (abs(E) / bar - 1.0))
        p_a += remain * q * p_here
        remain *= (1.0 - q)
        if remain <= 1e-12:
            break
    if remain > 1e-12:
        R = (E / M) if M > 1e-12 else 0.0
        p_a += remain * _sig(beta * c * _drive(R))

    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = (1.0 - eps) * p + eps * 0.5
    p = np.clip(p, 1e-12, None)
    p = p / p.sum()
    return p
```

**`policy(probs)`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))
```
