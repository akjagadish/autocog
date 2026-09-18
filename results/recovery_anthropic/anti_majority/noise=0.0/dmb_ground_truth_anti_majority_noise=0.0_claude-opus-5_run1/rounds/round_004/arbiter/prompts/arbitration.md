# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_5" and "pi_6") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_5" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_6" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_5
**PWA-DD: Position-Bound Weighted Additive integration with Faint-Praise discounting and Endorsement-Density Dilution.**

Choice in binary-cue environments is always *compensatory*: on every trial the decision maker reads all displayed columns, forms a single weighted difference, and never stops early. There is no lexicographic cascade and no coherence/unanimity premium. Three claims fix the rest of the mechanism.

(1) **Weights are a mixture of validity and display position, and the mixture is governed by how readable the validity-to-column mapping is.** Stated validities must be bound to *columns*. When the display is perfectly monotone in validity (ascending or descending) that binding is trivial and people use validity-derived weights w_val ∝ logit(v_j)^γ essentially intact (the residual positional leak μ0 is small and person-specific, and in some people is exactly zero). When the column order is not monotone in validity — and especially when the best expert sits in an interior column — binding fails and people fall back almost entirely on a purely positional gradient w_pos ∝ (n−j)^λ that decays left-to-right over displayed columns. The mixture weight μ = μ0 + (1−μ0)·min(1, μ1(1−|τ|) + μ2·[best cue interior]) is therefore an *environmental* quantity, not a per-experiment fudge: it is inert (μ = μ0) whenever columns are validity-sorted, and it predicts that scrambling a sorted display converts validity-driven behaviour into position-driven behaviour and that re-sorting a scrambled display restores it. Crucially the gate SATURATES: any display that is appreciably non-monotone is read essentially positionally, with no graded validity leak surviving.

(2) **Faint-praise endorsement discounting.** Each positive endorsement carries a small fixed credibility cost θ: an option that collects more '1's is slightly *less* attractive, all else equal. This is strictly monotone in endorsement count — there is no step at unanimity. It makes a lone weak endorsement no better (often slightly worse) than an empty panel, and it makes a 5/5 panel no better than a 4/5 panel by exactly the same amount, which is why 'high-coherence' and 'low-coherence' single-cue steps move together rather than apart. θ sits just at the subjective weight of the weakest experts — close enough that a lone weak endorsement is near-neutral to mildly counter-diagnostic rather than strongly aversive — while endorsement by a strong expert still wins comfortably.

(3) **Endorsement-density dilution of decision sensitivity.** The same absolute weighted difference is less decisive when both panels are densely endorsed. Evidence is divisively normalised by the mean endorsement density T = (Σa + Σb)/2n: D = [Σ_j w_j(a_j−b_j) − θ(Σa−Σb)] / (c0 + κ·T). The dilution has TWO separable constants: a floor c0 that sets how crisply *sparse* panels are compared, and a gain κ that sets how much extra mush dense panels accrue. The floor is *not* negligible: even near-empty panels are compared with bounded, distinctly sub-ceiling determinacy, which keeps lone-endorsement-versus-empty cells close to (rather than far below) chance and preserves the graded ladder structure of sparse comparisons. Heavily endorsed panels are compared mushily. Unlike a consensus premium, dilution is *direction-blind* — it never confers an advantage on the more coherent option, it only compresses whatever advantage exists — so it produces the observed shrinkage of a fixed one-cue advantage at high endorsement backgrounds without ever predicting a unanimity bonus.

p(A) = (1−ε)·logistic(βD) + ε/2. Everyone holds the same stationary rule (no feedback is given, so nothing is learned); heterogeneity is broad and continuous — in determinacy β, validity sensitivity γ, discount θ, positional decay λ, dilution (c0, κ), lapse ε and the readability coefficients — never discrete strategy switching. The theory therefore predicts substantial between-subject spread in every conflict metric, largest where margins are intermediate.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # PWA-DD: position-bound weighted additive integration with
    # faint-praise endorsement discounting and endorsement-density dilution.
    #
    #   w_val_j  proportional to logit(v_j) ** gamma      (validity weights)
    #   w_pos_j  proportional to (n - j) ** lam           (left-to-right gradient)
    #   mu       = mu0 + (1-mu0)*min(1, mu1*(1-|tau|) + mu2*[best cue interior])
    #   w        = (1-mu)*w_val + mu*w_pos                (normalised)
    #   num      = w.(a-b) - theta*(sum a - sum b)        (faint-praise discount)
    #   T        = (sum a + sum b) / (2n)                 (endorsement density)
    #   D        = num / (c0 + kap*T)                     (density dilution)
    #   p(A)     = (1-eps)*logistic(beta*D) + eps/2
    #
    # No stopping rule, no coherence/unanimity premium.  History unused:
    # the rule is stationary because no feedback is provided.
    import numpy as np

    # ---------------- unpack the two rating vectors --------------------
    a = None
    b = None
    if isinstance(state, dict):
        if "option_a_ratings" in state and "option_b_ratings" in state:
            a = np.asarray(state["option_a_ratings"], dtype=float).ravel()
            b = np.asarray(state["option_b_ratings"], dtype=float).ravel()
    if a is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 1:
            half = int(arr.shape[0] // 2)
            a = arr[:half].astype(float)
            b = arr[half:2 * half].astype(float)
        else:
            arr = arr.reshape(arr.shape[0], -1)
            a = arr[0].astype(float)
            b = arr[1].astype(float)

    n = int(min(np.size(a), np.size(b)))
    if n == 0:
        return np.array([0.5, 0.5])
    a = np.asarray(a, dtype=float).ravel()[:n]
    b = np.asarray(b, dtype=float).ravel()[:n]

    # ---------------- validities ---------------------------------------
    val = parameters.get("validities", None)
    if val is None:
        v = np.linspace(0.90, 0.55, n)
    else:
        v = np.asarray(val, dtype=float).ravel().astype(float)
        if v.shape[0] < n:
            v = np.concatenate([v, np.full(n - v.shape[0], 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5 + 1e-6, 1.0 - 1e-6)

    # ---------------- parameters ---------------------------------------
    gamma = float(parameters.get("gamma", 1.5))
    beta = float(parameters.get("beta", 3.8))
    theta = float(parameters.get("theta", 0.1075))
    c0 = float(parameters.get("c0", 0.09))
    kap = float(parameters.get("kap", 1.7))
    mu0 = float(np.clip(float(parameters.get("mu0", 0.07)), 0.0, 1.0))
    mu1 = float(parameters.get("mu1", 1.8))
    mu2 = float(parameters.get("mu2", 0.4))
    lam = float(parameters.get("lam", 0.95))
    eps = float(np.clip(float(parameters.get("eps", 0.125)), 0.0, 1.0))
    c0 = max(c0, 1e-3)

    # ---------------- validity-derived weights --------------------------
    L = np.log(v / (1.0 - v))
    L = np.maximum(L, 1e-9)
    with np.errstate(over="ignore", invalid="ignore"):
        wv = np.power(L, gamma)
    wv = np.nan_to_num(wv, nan=0.0, posinf=1e12, neginf=0.0)
    s = float(np.sum(wv))
    if (not np.isfinite(s)) or s <= 0.0:
        wv = np.ones(n, dtype=float) / float(n)
    else:
        wv = wv / s

    # ---------------- positional (reading-order) weights ----------------
    idx = np.arange(n, dtype=float)
    with np.errstate(over="ignore", invalid="ignore"):
        wp = np.power(np.maximum(float(n) - idx, 1e-9), lam)
    wp = np.nan_to_num(wp, nan=0.0, posinf=1e12, neginf=0.0)
    s = float(np.sum(wp))
    if (not np.isfinite(s)) or s <= 0.0:
        wp = np.ones(n, dtype=float) / float(n)
    else:
        wp = wp / s

    # ---------------- display readability -------------------------------
    # Kendall tau between column index and stated validity (ties skipped).
    conc = 0
    disc = 0
    for i in range(n - 1):
        for j in range(i + 1, n):
            d = v[j] - v[i]
            if d > 0:
                conc += 1
            elif d < 0:
                disc += 1
    tot = conc + disc
    tau = 0.0 if tot == 0 else float(conc - disc) / float(tot)
    incong = 1.0 - abs(tau)                     # 0 when display is monotone
    jmax = int(np.argmax(v))
    interior = 0.0 if (jmax == 0 or jmax == n - 1) else 1.0

    mu = mu0 + (1.0 - mu0) * min(1.0, max(0.0, mu1 * incong + mu2 * interior))
    mu = float(np.clip(mu, 0.0, 1.0))

    w = (1.0 - mu) * wv + mu * wp
    s = float(np.sum(w))
    if (not np.isfinite(s)) or s <= 0.0:
        w = np.ones(n, dtype=float) / float(n)
    else:
        w = w / s

    # ---------------- evidence ------------------------------------------
    core = float(np.dot(w, a - b))
    cnt_a = float(np.sum(a))
    cnt_b = float(np.sum(b))
    num = core - theta * (cnt_a - cnt_b)          # faint-praise discount

    dens = (cnt_a + cnt_b) / (2.0 * float(n))     # endorsement density in [0,1]
    denom = c0 + kap * dens
    if (not np.isfinite(denom)) or denom <= 1e-6:
        denom = 1e-6
    D = num / denom

    # ---------------- logistic choice with lapse -------------------------
    z = np.array([beta * D, 0.0], dtype=float)
    z = z - np.max(z)
    e = np.exp(z)
    p_core = e / np.sum(e)

    p = (1.0 - eps) * p_core + eps * 0.5
    p = np.clip(p, 1e-12, 1.0)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    p = np.asarray(probs, dtype=np.float64).ravel()
    p = np.clip(p, 0.0, None)
    tot = p.sum()
    if (not np.isfinite(tot)) or tot <= 0.0:
        p = np.ones_like(p) / float(len(p))
    else:
        p = p / tot
    return int(np.random.choice(len(p), p=p))

## THEORY 2 — pi_6
**ERC-SB (determinacy-corrected): Expectation-Referenced Cue Coding with Saturating Deviation Value, Compressed Endorsement Numerosity, and *Binding-Conditional* Contrast Compression.**

Choice between two binary-cue panels is compensatory, stationary (no feedback is given, so nothing is learned), and rests on one idea: every displayed rating is scored *relative to a subjective endorsement expectation*, and both the deviation from that expectation and the endorsement surplus it is charged against are perceived on compressed psychophysical scales.

(1) *Signed, expectation-referenced cue coding.* Expert j's stated validity is converted to diagnosticity x_j = (logit v_j)^gamma, and the decision maker holds a reference endorser v* with diagnosticity theta = (logit v*)^gamma. A '1' is good news only to the extent that the endorsing expert is more discriminating than the reference; approval from a sub-reference endorser is faint praise and is genuinely counter-diagnostic. This single mechanism replaces both a unanimity premium and a uniform endorsement discount.

(2) *Diminishing sensitivity about the reference.* Subjective value is an S-shaped function of the deviation from the expectation reference, x~_j = theta + A*tanh(s*(x_j - theta)/A): sharp discrimination near v*, saturation on both branches. People categorise experts as 'better' or 'worse' than their reference endorser, so all clearly sub-reference endorsers are about equally damning.

(3) *Compressed endorsement numerosity.* The expectation charge is levied on the compressed magnitude of the endorsement surplus m: charge = theta*sign(m)*|m|^zeta, zeta < 1 (Weber-like). One extra endorsement is felt far more sharply than the fifth relative to the fourth.

(4) *Contrast-count normalisation that is background-blind but binding-conditional.* Sensitivity is divided by a term that grows with the number K of columns on which the panels actually disagree and is completely blind to the shared endorsement background: density ladders with fixed contrast and coherence must be FLAT. The cost of reconciling many simultaneous contrasts depends on whether the validity-to-column mapping has been successfully bound. When the display is validity-monotone, each discriminating column is read off cheaply and the cost is linear in K. When binding has failed (scrambled display / interior best expert), each additional discriminating column must be held in mind without a stable importance anchor, so cost grows *super*-linearly: denom = c0 + kappa*K*(1 + delta*mu^2*(K-1)). Scrambling a display therefore flattens *large* contrasts far more than small ones.

(5) *Readability / column binding.* When the display is monotone in validity (either direction) binding is trivial and the signed values are used intact; when the mapping is scrambled - especially with the best expert interior - values flatten toward their mean and a left-to-right reading gradient is recruited.

(6) *Population structure and determinacy.* One stationary rule for everyone, with broad continuous heterogeneity in determinacy beta, validity sensitivity gamma, crossover v*, reference-sensitivity (A, s), numerosity exponent zeta, normalisation (c0, kappa, delta), reading gradient rho and lapse eps. The added commitment of this version is that *attentional lapsing is rare*: essentially all of the observed regression toward chance is produced by the evidence transformation itself (expectation-referenced saturation and contrast-count normalisation), not by stimulus-independent guessing. Choices are therefore more determinate than a large-lapse account would allow, and the shrinkage of any given contrast must be predictable from its K, its endorsement surplus and the readability of the display - never from a free global guess rate. No discrete strategy switching, no learning, no consensus premium, no density dilution.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # ERC-SB: Expectation-Referenced Cue Coding with an S-shaped (saturating)
    #         deviation value, compressed endorsement numerosity and
    #         BINDING-CONDITIONAL contrast-count normalisation.
    #
    #   x_j     = logit(v_j) ** gamma                (raw diagnosticity)
    #   theta   = logit(v*) ** gamma                 (subjective endorsement expectation)
    #   x~_j    = theta + A*tanh(sl*(x_j-theta)/A)   (diminishing sensitivity about theta,
    #                                                 A = alpha*theta)
    #   mu      = readability gate (0 = validity-sorted display, 1 = unreadable)
    #   xf_j    = (1-mu)*x~_j + mu*mean(x~)          (flatten toward equal weighting)
    #   g_j     = ((n-j)/n)^lam  (centred)           (left-to-right reading gradient)
    #   w_j     = xf_j + rho*mu*g_j
    #   m       = sum(a) - sum(b)                    (endorsement surplus)
    #   num     = sum_j w_j (a_j-b_j) - theta*sign(m)*|m|^zeta   (compressed charge)
    #   K       = number of discriminating columns
    #   D       = num / (c0 + kap*K*(1 + delta*mu^2*(K-1)))      (super-linear only
    #                                                 when column binding has failed)
    #   p(A)    = (1-eps)*logistic(beta*D) + eps/2
    #
    # No density dilution, no coherence/unanimity premium, no learning.
    import numpy as np

    # ---------------- unpack the two rating vectors --------------------
    a = None
    b = None
    if isinstance(state, dict):
        if "option_a_ratings" in state and "option_b_ratings" in state:
            a = np.asarray(state["option_a_ratings"], dtype=float).ravel()
            b = np.asarray(state["option_b_ratings"], dtype=float).ravel()
    if a is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 1:
            half = int(arr.shape[0] // 2)
            a = arr[:half].astype(float)
            b = arr[half:2 * half].astype(float)
        else:
            arr = arr.reshape(arr.shape[0], -1)
            a = arr[0].astype(float)
            b = arr[1].astype(float)

    a = np.asarray(a, dtype=float).ravel()
    b = np.asarray(b, dtype=float).ravel()
    n = int(min(a.shape[0], b.shape[0]))
    if n == 0:
        return np.array([0.5, 0.5])
    a = a[:n]
    b = b[:n]

    # ---------------- validities ---------------------------------------
    val = parameters.get("validities", None)
    if val is None:
        v = np.linspace(0.90, 0.55, n)
    else:
        v = np.asarray(val, dtype=float).ravel().astype(float)
        if v.shape[0] < n:
            v = np.concatenate([v, np.full(n - v.shape[0], 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5 + 1e-6, 1.0 - 1e-6)

    # ---------------- parameters ---------------------------------------
    gamma = float(parameters.get("gamma", 1.5))
    vstar = float(np.clip(float(parameters.get("vstar", 0.855)), 0.51, 0.99))
    beta = float(parameters.get("beta", 0.62))
    alpha = float(np.clip(float(parameters.get("alpha", 1.0)), 0.05, 5.0))
    sl = float(max(float(parameters.get("sl", 2.3)), 0.05))
    zeta = float(np.clip(float(parameters.get("zeta", 0.70)), 0.05, 1.0))
    c0 = max(float(parameters.get("c0", 0.425)), 1e-3)
    kap = max(float(parameters.get("kap", 0.65)), 1e-3)
    delta = max(float(parameters.get("delta", 0.85)), 0.0)
    mu0 = float(np.clip(float(parameters.get("mu0", 0.05)), 0.0, 1.0))
    mu1 = float(parameters.get("mu1", 1.9))
    mu2 = float(parameters.get("mu2", 0.6))
    rho = float(parameters.get("rho", 4.9))
    lam = float(parameters.get("lam", 1.0))
    eps = float(np.clip(float(parameters.get("eps", 0.025)), 0.0, 1.0))

    # ---------------- diagnosticity and expectation reference -----------
    L = np.log(v / (1.0 - v))
    L = np.maximum(L, 1e-9)
    with np.errstate(over="ignore", invalid="ignore"):
        x = np.power(L, gamma)
    x = np.nan_to_num(x, nan=0.0, posinf=1e9, neginf=0.0)

    Ls = np.log(vstar / (1.0 - vstar))
    Ls = max(Ls, 1e-9)
    with np.errstate(over="ignore", invalid="ignore"):
        theta = float(np.power(Ls, gamma))
    if not np.isfinite(theta) or theta <= 0.0:
        theta = float(np.mean(x)) if np.isfinite(np.mean(x)) else 1.0

    # ---- diminishing sensitivity about the expectation reference -------
    A = max(alpha * theta, 1e-6)
    with np.errstate(over="ignore", invalid="ignore"):
        x = theta + A * np.tanh(sl * (x - theta) / A)
    x = np.nan_to_num(x, nan=0.0, posinf=1e9, neginf=-1e9)

    # ---------------- readability of the validity->column mapping -------
    conc = 0
    disc = 0
    for i in range(n - 1):
        for j in range(i + 1, n):
            d = v[j] - v[i]
            if d > 0:
                conc += 1
            elif d < 0:
                disc += 1
    tot = conc + disc
    tau = 0.0 if tot == 0 else float(conc - disc) / float(tot)
    incong = 1.0 - abs(tau)                      # 0 when display is monotone
    jmax = int(np.argmax(v))
    interior = 0.0 if (jmax == 0 or jmax == n - 1) else 1.0

    gate = mu1 * incong + mu2 * interior
    gate = min(1.0, max(0.0, gate))
    mu = mu0 + (1.0 - mu0) * gate
    mu = float(np.clip(mu, 0.0, 1.0))

    # ---------------- flattening + positional gradient ------------------
    xbar = float(np.mean(x))
    xt = (1.0 - mu) * x + mu * xbar

    idx = np.arange(n, dtype=float)
    with np.errstate(over="ignore", invalid="ignore"):
        pos = np.power(np.maximum((float(n) - idx) / float(n), 1e-9), lam)
    pos = np.nan_to_num(pos, nan=0.0, posinf=1.0, neginf=0.0)
    g = pos - float(np.mean(pos))                # zero-mean reading gradient

    w = xt + rho * mu * g                        # column values (pre-expectation)

    # ---------------- evidence -----------------------------------------
    diff = a - b
    K = float(np.sum(np.abs(diff) > 1e-9))
    if K < 1.0:
        return np.array([0.5, 0.5])

    core = float(np.dot(w, diff))
    m = float(np.sum(a) - np.sum(b))             # endorsement surplus
    charge = theta * float(np.sign(m)) * (abs(m) ** zeta)
    num = core - charge

    # BINDING-CONDITIONAL contrast compression: linear in K when the
    # validity->column mapping is readable (mu ~ 0), super-linear when
    # binding has failed (mu ~ 1).  Still background-blind.
    bind_fail = mu * mu
    denom = c0 + kap * K * (1.0 + delta * bind_fail * max(K - 1.0, 0.0))
    if (not np.isfinite(denom)) or denom <= 1e-6:
        denom = 1e-6
    D = num / denom
    if not np.isfinite(D):
        D = 0.0

    # ---------------- logistic choice with lapse -------------------------
    z = np.array([beta * D, 0.0], dtype=float)
    z = z - np.max(z)
    e = np.exp(z)
    p_core = e / np.sum(e)

    p = (1.0 - eps) * p_core + eps * 0.5
    p = np.clip(p, 1e-12, 1.0)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    p = np.asarray(probs, dtype=np.float64).ravel()
    p = np.clip(p, 0.0, None)
    tot = p.sum()
    if (not np.isfinite(tot)) or tot <= 0.0:
        p = np.ones_like(p) / float(len(p))
    else:
        p = p / tot
    return int(np.random.choice(len(p), p=p))

## EXPERIMENT 1 (proposed by pi_5)

### DESIGN
**Validities (n_features=6):** [0.95, 0.86, 0.78, 0.7, 0.62, 0.54]

**Trial pairs (n=24):**
  trial 1: A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 2: A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 3: A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 4: A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0]
  trial 7: A=[1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  trial 8: A=[1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1]
  trial 9: A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  trial 10: A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0]
  trial 11: A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  trial 12: A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  trial 13: A=[0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 14: A=[0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  trial 15: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  trial 16: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  trial 17: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  trial 18: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  trial 19: A=[0, 1, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0]
  trial 20: A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1]
  trial 21: A=[0, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0]
  trial 22: A=[0, 1, 0, 0, 1, 0]  B=[1, 1, 0, 1, 0, 0]
  trial 23: A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]
  trial 24: A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Rationale:** GOAL: dissociate PWA-DD (advocated) from ERC-SB (competing). Both are compensatory and share logit-validity diagnosticity, and both contain the same readability gate, so I remove the readability nuisance entirely by displaying six experts in strictly DESCENDING validity (.95,.86,.78,.70,.62,.54): Kendall tau = -1 (incongruence 0) and the best expert sits in an extreme column, so mu = mu0 (<=.14 / <=.10) for both models. ERC's super-linear binding-failure term is therefore inert and its normaliser is exactly c0+kappa*K. All remaining differences are attributable to the three rival post-integration mechanisms: PWA-DD's endorsement-DENSITY dilution (divide by c0+kap*T, background-sensitive, contrast-count-blind) with a LINEAR faint-praise discount theta calibrated to the weakest cues, versus ERC-SB's expectation-referenced saturating cue values (everything below v* in [.80,.90] is strongly and near-EQUALLY counter-diagnostic), its COMPRESSED numerosity charge theta*|m|^zeta, and its CONTRAST-COUNT normalisation (divide by c0+kap*K, density-blind).

Mid-parameter PWA weights (gamma=1.5, normalised): [.500,.242,.141,.077,.034,.006]; theta ~ .108. Mid-parameter ERC saturated values (v*=.85,gamma=1.5,sl=2.3,alpha=1): [4.55,2.65,0.69,0.21,0.09,0.05] against a reference charge theta = 2.28 per endorsement. 12 base pairs, each mirrored (A/B swapped) so neither key is systematically correct: 24 unique pairs, K = 4 repetitions, 96 trials.

FAMILY V - SINGLE ENDORSEMENT vs AN EMPTY PANEL, SWEPT ACROSS CUE VALIDITY (pairs 1-6 + mirrors). One option carries exactly one '1' (on col0..col5 in turn), the other is all zeros; K=1 and m=+1 in every cell, so ERC's normaliser and charge are identical throughout and only the cue's subjective value moves. PWA-DD predicts a SMOOTH GRADED LADDER that crosses chance between col2 and col3 and keeps descending: ~ .94 / .85 / .62 / .39 / .26 / .20. ERC-SB predicts a STEP followed by a SATURATED FLOOR: ~ .77 / .55 / .29 / .24 / .23 / .23 - cols 2-5 are all sub-reference and, because of the tanh saturation, essentially indistinguishable, and col2 (.78) is REVERSED relative to PWA-DD. The two critical contrasts are (i) V3 vs V5: PWA-DD says a ~19-point spread among the three weakest experts, ERC-SB says <2 points; (ii) V2: PWA-DD says at-or-above chance, ERC-SB says clearly below chance.

FAMILY T - PURE DENSITY LADDER WITH K, CORE AND COUNT DIFFERENCE HELD EXACTLY CONSTANT (pairs 1, 7, 9, 8 + mirrors: shared background k = 0, 1, 2, 5). In all four cells the options differ on col0 and ONLY col0 (K=1, m=+1), so ERC's evidence, charge and normaliser are literally identical and it must be COMPLETELY FLAT at ~.77. PWA-DD divides by c0+kap*T with T = .083/.25/.417/.917 and predicts a large monotone decay ~ .94 / .89 / .82 / .69 that never crosses chance. Flat-versus-25-point-decline with everything else pinned is the cleanest possible test of density dilution against a background-blind account.

FAMILY K - PURE CONTRAST-COUNT LADDER WITH DENSITY, COUNT DIFFERENCE AND CORE HELD ~CONSTANT (pairs 9, 10, 11 + mirrors). All three cells have sum(a)=3, sum(b)=2 (so T=5/12 and m=+1 are identical, making PWA's dilution and discount identical), the col0 (.95) contrast always favours A, and the extra discriminating columns are drawn from the saturated weak cluster so that they nearly cancel: K = 1, 3, 5. PWA-DD has NO contrast-count term and predicts a flat ~ .82 / .84 / .77. ERC-SB divides by c0+kap*K (1.08 / 2.38 / 3.68) and predicts a steep monotone compression ~ .77 / .64 / .57. This is the mirror-image test of Family T and is diagnostic even if one doubts my density claim.

FAMILY D - DOMINANCE ANCHOR (pair 12 + mirror): [1,1,1,1,1,1] vs [0,0,0,0,0,0]. Under PWA-DD the linear discount removes 6*theta from a core of 1 and the density T=.5 dilutes, leaving a clearly above-chance ~.77-.85. Under ERC-SB the compressed charge theta*6^zeta (~8.0-11.4) very nearly cancels or exceeds the summed saturated evidence (~7.8-8.4) and K=6 crushes the normaliser, so it predicts a striking NEAR-CHANCE (.45-.57) response to a fully dominant option. A high-accuracy dominance cell also pins beta and eps for PWA-DD, making Families V, T and K out-of-sample predictions rather than free fits.

DECISION RULE. If PWA-DD is right: Family V is a smooth graded ladder with the three weakest experts clearly separated and col2 at/above chance; Family T declines steeply and monotonically with shared endorsement background; Family K is FLAT across contrast counts; dominance is comfortably above chance. If ERC-SB is right: Family V shows a saturated floor (V2=V3=V4=V5) with col2 already strongly reversed; Family T is perfectly FLAT; Family K falls steeply with the number of discriminating columns; and the dominance pair sits near chance. Between-subject spread should be largest at V1 (col1 = .86 straddles ERC's v* box) and at V2/K1 (PWA's w2 straddles its theta box) under the respective accounts.

**Computed schedule:** 24 unique pairs × 4 reps = 96 trials per subject.



### METRIC
Rationale:
PWA-DD and ERC-SB differ systematically in HOW OFTEN the option endorsed by the leading discriminating expert is chosen, and the differences are largest in a specific subset of cells. Rather than betting everything on one fragile per-cell contrast (8 trials/cell -> binomial sd ~0.15), I aggregate a weighted average of 'target rates' across eight cells whose predicted PWA-minus-ERC gaps are all positive and sizeable: lone-endorsement cells V0/V1/V2/V3 (PWA: smooth graded ladder .94/.85/.62/.39; ERC: step then saturated floor .77/.55/.29/.24), the contrast-count cells K3/K5 (PWA flat ~.84/.77 because it has no K normaliser; ERC compressed to ~.64/.57), the one-endorsement-background col0 contrast T1 (.89 vs .77) and the dominance pair (PWA comfortably above chance ~.81; ERC crushed near chance ~.51 by its compressed numerosity charge plus K=6 normalisation). Weights are proportional to the expected gap, so the metric is essentially the optimal linear discriminant over cells. Predicted values: ~0.75 under PWA-DD vs ~0.51 under ERC-SB (gap ~0.24). Because it pools ~64 trials per subject, binomial noise contributes only sd ~0.055 per subject, and the remaining between-subject spread comes from determinacy/lapse heterogeneity, which is modest relative to the mean gap. The metric is computable identically on the pooled frame and on any single subject's slice.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Weighted mean 'target rate' over a selected set of stimulus cells.
    # 'Target' on a trial = the option carrying the 1 in the LEFTMOST column
    # on which the two panels disagree (i.e. the option endorsed by the most
    # valid discriminating expert).  Cells are keyed mirror-invariantly as
    # "<target panel>|<other panel>".
    W = {
        "100000|000000": 1.0,   # V0 : lone .95 endorsement vs empty panel
        "010000|000000": 2.0,   # V1 : lone .86 endorsement vs empty panel
        "001000|000000": 2.0,   # V2 : lone .78 endorsement vs empty panel
        "000100|000000": 1.0,   # V3 : lone .70 endorsement vs empty panel
        "110000|010000": 0.8,   # T1 : col0 contrast on a 1-endorsement background
        "110100|010010": 1.5,   # K3 : three discriminating columns, col0 leads
        "100101|001010": 1.5,   # K5 : five discriminating columns, col0 leads
        "111111|000000": 2.0,   # D  : full dominance
    }

    hits = {}
    tot = {}

    a_col = data["option_a_ratings"].tolist()
    b_col = data["option_b_ratings"].tolist()
    r_col = data["response"].tolist()

    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        try:
            a = [int(round(float(x))) for x in list(a_raw)]
            b = [int(round(float(x))) for x in list(b_raw)]
        except Exception:
            continue
        n = min(len(a), len(b))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        first = -1
        for j in range(n):
            if a[j] != b[j]:
                first = j
                break
        if first < 0:
            continue
        if a[first] == 1:
            tgt = a
            oth = b
            tgt_resp = 0
        else:
            tgt = b
            oth = a
            tgt_resp = 1
        key = "".join([str(v) for v in tgt]) + "|" + "".join([str(v) for v in oth])
        if key not in W:
            continue
        try:
            rr = int(resp)
        except Exception:
            continue
        tot[key] = tot.get(key, 0) + 1
        if rr == tgt_resp:
            hits[key] = hits.get(key, 0) + 1
        else:
            hits[key] = hits.get(key, 0)

    num = 0.0
    den = 0.0
    for k, w in W.items():
        if tot.get(k, 0) > 0:
            rate = float(hits.get(k, 0)) / float(tot[k])
            num += w * rate
            den += w
    if den <= 0.0:
        return float("nan")
    return float(num / den)

### RESULTS
- Predicted under pi_5 (simulated): 0.7383 (var=0.0055)
- Predicted under pi_6 (simulated): 0.5204 (var=0.0045)
- Observed on real data: 0.1354 (var=0.0056)

## EXPERIMENT 2 (proposed by pi_6)

### DESIGN
**Validities (n_features=6):** [0.95, 0.91, 0.85, 0.74, 0.64, 0.55]

**Trial pairs (n=24):**
  trial 1: A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 3: A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 4: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  trial 5: A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  trial 7: A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  trial 9: A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  trial 10: A=[0, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0]
  trial 11: A=[1, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1]
  trial 12: A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1]
  trial 13: A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  trial 14: A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  trial 15: A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  trial 16: A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1, 0]
  trial 17: A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  trial 18: A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  trial 19: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  trial 20: A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 21: A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  trial 22: A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 23: A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  trial 24: A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Rationale:** GOAL: dissociate ERC-SB (advocated) from PWA-DD (competing). Both are compensatory, share logit-validity diagnosticity and contain the SAME readability gate, so I remove the readability nuisance entirely: six experts are displayed in strictly DESCENDING validity (.95,.91,.85,.74,.64,.55). Kendall tau = -1 (incongruence 0) and the best expert sits in an extreme column, so mu = mu0 (<=.10 / <=.14) for both models; ERC's super-linear binding-failure term is inert (its normaliser reduces to c0+kap*K) and PWA's positional fallback is inert. Every remaining prediction difference is therefore attributable to the three rival post-integration mechanisms: (i) ERC's EXPECTATION-REFERENCED SATURATION (tanh about theta = logit(v*)^gamma, v* in [.80,.90]) versus PWA's linear normalised validity weights; (ii) ERC's CONTRAST-COUNT normalisation (divide by c0+kap*K, completely background-blind) versus PWA's ENDORSEMENT-DENSITY dilution (divide by c0+kap*T, completely contrast-count-blind); (iii) ERC's COMPRESSED numerosity charge theta*|m|^zeta versus PWA's LINEAR faint-praise discount theta*m.

Mid-parameter quantities. ERC (gamma=1.5, v*=.85 -> theta=2.284, alpha=1, sl=2.3, zeta=.7, c0=.425, kap=.65, beta=.62): saturated column values [4.55, 4.22, 2.28, 0.37, 0.11, 0.05] against a per-endorsement charge of 2.28. PWA (gamma=1.5, theta=.108, c0=.09, kap=1.7, beta=3.8, eps=.125): normalised weights [.406, .283, .184, .086, .035, .007].

12 base pairs, each mirrored (A/B swapped) so neither response key is systematically correct: 24 unique pairs, K = 4 repetitions, 96 trials.

FAMILY T ation - PURE DENSITY LADDER WITH K, CORE AND COUNT DIFFERENCE PINNED (pairs 1, 5, 6 + mirrors). The two options differ on col0 (.95) and ONLY col0, with a shared background of k = 0, 2, 5 ones, so K=1, m=+1 and the weighted core are literally identical in all three cells; only total endorsement density T (=.083/.417/.917) moves. ERC-SB is background-blind and must be PERFECTLY FLAT at ~.78. PWA-DD divides by c0+kap*T and predicts a large monotone decay ~.93 / .77 / .65. Flat versus a ~28-point decline, with everything else pinned, is the cleanest possible test of density dilution.

FAMILY K - PURE CONTRAST-COUNT LADDER WITH DENSITY, COUNTS AND PWA-CORE PINNED (pairs 7, 8, 9 + mirrors). All three cells have sum(a)=sum(b)=3 (so m=0: BOTH discount terms are exactly inert) and T=.5 exactly, and the PWA weighted core is matched to within 10% (.320 / .348 / .350), while the number of discriminating columns is K = 2, 4, 6. PWA-DD has no contrast-count term and must be FLAT (~.75 / .77 / .77, if anything rising). ERC-SB divides by c0+kap*K (1.725 / 3.025 / 4.325) and predicts a steep monotone compression ~.82 / .70 / .60. This is the exact mirror-image of Family T, so the two families cross: whichever model is right must be flat on one ladder and steep on the other.

FAMILY V - SATURATION FLOOR VERSUS GRADED LADDER (pairs 1, 2, 3, 4 + mirrors). One option carries exactly one '1' (on col0=.95, col2=.85, col3=.74 or col5=.55) and the other is all zeros; K=1 and m=+1 throughout, so ERC's normaliser and charge are identical and only the cue's subjective value moves. ERC-SB predicts .78 / .50 / .25 / .22: a saturated FLOOR in which the .74 and .55 experts are essentially indistinguishable (<4 points apart) because both are clearly below the endorsement reference, and the .85 expert sits at almost exactly chance (it straddles the v* box, so this cell should also show the LARGEST between-subject spread in the design). PWA-DD predicts a SMOOTH GRADED ladder .93 / .74 / .42 / .20 - a 22-point separation between col3 and col5 and a solidly above-chance col2. The two critical contrasts are V3-vs-V5 (flat vs 22 points) and V2 (chance vs clearly above chance).

FAMILY S - POSITIVE-BRANCH SATURATION (pairs 10, 11 + mirrors). Only two columns discriminate, counts are equal (m=0, both discount terms inert) and density is identical, so this is a pure cue-value contrast. S1 pits col0 (.95) against col1 (.91): both are far ABOVE the reference, so ERC's tanh flattens them to near-equality (value gap 0.34 out of ~4.5) and it predicts near-chance ~.53-.60; PWA's weights differ substantially (.406 vs .283) and it predicts ~.74. S2 pits col0 against col2 (.85): ERC ~.69, PWA ~.86. The ERC-specific quantitative claim is the RATIO: the .95-vs-.91 contrast must be far closer to chance relative to the .95-vs-.85 contrast (ERC value ratio .15) than any linear validity weighting allows (PWA ratio .55).

FAMILY D - DOMINANCE ANCHOR / NUMEROSITY COMPRESSION (pair 12 + mirror): [1,1,1,1,1,1] vs [0,0,0,0,0,0]. PWA-DD subtracts a linear 6*theta from a core of 1 and divides by c0+kap*.5, leaving a comfortably above-chance ~.77-.85 - this cell also pins its beta and eps, making Families T, K, V and S out-of-sample predictions rather than free fits. ERC-SB's COMPRESSED charge theta*6^zeta (~5.0-10.1) eats most of the summed saturated evidence (~11.6) and K=6 crushes the normaliser, so it predicts a striking NEAR-CHANCE (.55-.65) response to a fully dominant option.

DECISION RULE. If ERC-SB is right: Family T is perfectly flat across the shared endorsement background; Family K falls steeply (~20 points) with the number of discriminating columns; Family V shows a saturated floor (V3 = V5) with the .85 cell at chance; S1 is near chance while S2 is clearly above it; and full dominance is only weakly above chance. If PWA-DD is right: Family T declines steeply and monotonically; Family K is flat; Family V is a smooth graded ladder separating the three weak experts; S1 is clearly above chance; and dominance is decisively above chance.

**Computed schedule:** 24 unique pairs × 4 reps = 96 trials per subject.



### METRIC
Rationale:
The design contains cells whose predicted choice rates move in OPPOSITE directions under the two theories, so I build a single contrast that adds those gaps rather than differencing noisy single cells.

Working through both models at mid-range parameters (validities [.95,.91,.85,.74,.64,.55], display validity-sorted so both readability gates are inert):

Group P (PWA >> ERC): lone .95 cue vs empty (ERC .78 / PWA .93); lone .85 cue vs empty (ERC ~.50, exactly at chance because .85 sits at the expectation reference / PWA .74); lone .74 cue vs empty (ERC .25 / PWA .44); .95-vs-.91 (ERC ~.53, tanh saturation flattens the two strong experts / PWA .74); .95-vs-.85 (ERC .69 / PWA .85); the six-discriminating-column conflict (ERC .60 because the normaliser c0+kap*K explodes / PWA .76, contrast-count-blind); and full dominance (ERC .62 because the compressed numerosity charge theta*6^zeta eats the evidence / PWA .77).

Group N (ERC > PWA): the same lone .95 advantage on a fully dense background (ERC .78, background-blind / PWA .64, density-diluted) and the two-column conflict (ERC .81 / PWA .74).

Metric = mean(P hits) - mean(N hits). Predicted: ERC-SB ~ -0.22, PWA-DD ~ +0.06, a ~0.28 gap. Crucially the P group pools 56 trials per subject and mixes cells that move in opposite directions under determinacy (beta) heterogeneity, so individual-parameter noise partially cancels: recomputing ERC at beta=0.40 vs 0.88 shifts the P mean only from .55 to .59, and eps/beta heterogeneity in PWA compresses everything toward .5 symmetrically. That gives a large mean separation with a tight per-subject distribution.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    # ---- cell definitions -------------------------------------------------
    # Each entry is (designated_option, other_option).  We score the fraction
    # of trials on which the subject chose the designated option.
    # Group P: cells where PWA-DD predicts a MUCH higher rate than ERC-SB.
    P_list = [
        ((1, 0, 0, 0, 0, 0), (0, 0, 0, 0, 0, 0)),   # V0 : lone .95 cue, sparse
        ((0, 0, 1, 0, 0, 0), (0, 0, 0, 0, 0, 0)),   # V2 : lone .85 cue (ERC ~ chance)
        ((0, 0, 0, 1, 0, 0), (0, 0, 0, 0, 0, 0)),   # V3 : lone .74 cue
        ((1, 0, 0, 0, 0, 0), (0, 1, 0, 0, 0, 0)),   # S1 : .95 vs .91 (ERC saturated)
        ((1, 0, 0, 0, 0, 0), (0, 0, 1, 0, 0, 0)),   # S2 : .95 vs .85
        ((1, 0, 1, 1, 0, 0), (0, 1, 0, 0, 1, 1)),   # K6 : six discriminating columns
        ((1, 1, 1, 1, 1, 1), (0, 0, 0, 0, 0, 0)),   # D  : full dominance
    ]
    # Group N: cells where ERC-SB predicts a HIGHER rate than PWA-DD.
    N_list = [
        ((1, 1, 1, 1, 1, 1), (0, 1, 1, 1, 1, 1)),   # lone .95 cue on a dense background
        ((1, 1, 0, 0, 1, 0), (0, 1, 0, 1, 1, 0)),   # K2 : only two discriminating columns
    ]

    def sig(u, v):
        return tuple(sorted([tuple(u), tuple(v)]))

    Pmap = {}
    for w, o in P_list:
        Pmap[sig(w, o)] = w
    Nmap = {}
    for w, o in N_list:
        Nmap[sig(w, o)] = w

    p_hit = 0.0
    p_n = 0.0
    n_hit = 0.0
    n_n = 0.0

    for a_raw, b_raw, r in zip(data['option_a_ratings'].values,
                               data['option_b_ratings'].values,
                               data['response'].values):
        try:
            a = tuple(int(round(float(x))) for x in a_raw)
            b = tuple(int(round(float(x))) for x in b_raw)
        except Exception:
            continue
        k = sig(a, b)
        win = Pmap.get(k, None)
        grp = 'P'
        if win is None:
            win = Nmap.get(k, None)
            grp = 'N'
        if win is None:
            continue
        try:
            resp = int(r)
        except Exception:
            continue
        chosen = a if resp == 0 else b
        hit = 1.0 if chosen == win else 0.0
        if grp == 'P':
            p_hit += hit
            p_n += 1.0
        else:
            n_hit += hit
            n_n += 1.0

    if p_n == 0.0 and n_n == 0.0:
        return float('nan')
    if p_n == 0.0:
        return float(0.5 - (n_hit / n_n))
    if n_n == 0.0:
        return float((p_hit / p_n) - 0.75)
    return float((p_hit / p_n) - (n_hit / n_n))


### RESULTS
- Predicted under pi_5 (simulated): 0.0777 (var=0.0134)
- Predicted under pi_6 (simulated): -0.2268 (var=0.0138)
- Observed on real data: -0.0043 (var=0.0107)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = 0.0
    n = 0.0
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float).ravel()
        b = np.asarray(row['option_b_ratings'], dtype=float).ravel()
        if a.shape[0] != b.shape[0] or a.shape[0] == 0:
            continue
        # Take-The-Best winner: first discriminating cue in validity order.
        # Feature columns are already ordered by descending validity in this design.
        ttb_winner = None
        for j in range(a.shape[0]):
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner is None:
            continue
        # Tallying winner: majority of feature-wise wins (ties excluded).
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins == b_wins:
            continue
        tally_winner = 0 if a_wins > b_wins else 1
        if tally_winner == ttb_winner:
            continue  # not a conflict trial
        resp = row['response']
        if resp is None or (isinstance(resp, float) and np.isnan(resp)):
            continue
        hits += 1.0 if int(resp) == ttb_winner else 0.0
        n += 1.0

    if n == 0.0:
        return 0.5
    return float(hits / n)
```

**Observed (real) value:** 0.7533 (var=0.0228)
**Predicted under pi_5:** 0.7683 (var=0.0072)
**Predicted under pi_6:** 0.7375 (var=0.0114)

### Experiment 4
**Design**
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Fixed design validities: f0=.93, f1=.58, f2=.86, f3=.51, f4=.74, f5=.65
    val = np.array([0.93, 0.58, 0.86, 0.51, 0.74, 0.65], dtype=float)

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    hits = 0
    n = 0
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float)
        b = np.asarray(b_raw, dtype=float)
        if a.shape[0] != b.shape[0]:
            continue
        if a.shape[0] == val.shape[0]:
            order = np.argsort(-val, kind='stable')
        else:
            order = np.arange(a.shape[0])

        tally = int(np.sum(a > b)) - int(np.sum(b > a))

        winner = None
        for j in order:
            j = int(j)
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
        if winner is None:
            continue  # no cue discriminates: uninformative for both models

        ttb_sign = 1 if winner == 0 else -1
        # Keep only trials where the tally does NOT favour the TTB winner:
        # either the tally is exactly tied (Family D) or it points the
        # other way (Family E, directional conflict).
        if tally * ttb_sign > 0:
            continue

        n += 1
        try:
            resp = int(r)
        except Exception:
            continue
        if resp == winner:
            hits += 1

    if n == 0:
        return 0.5
    return float(hits) / float(n)
```

**Observed (real) value:** 0.5100 (var=0.0136)
**Predicted under pi_5:** 0.4938 (var=0.0059)
**Predicted under pi_6:** 0.5188 (var=0.0047)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    validities = [0.55, 0.62, 0.70, 0.85, 0.93]

    def key(v):
        return ''.join([str(int(round(float(x)))) for x in v])

    # conflict families: TTB (top-validity cue) and a left-to-right positional
    # weighting scheme point to OPPOSITE options
    conflict_keys = {
        '10000|00001', '00001|10000',      # family A
        '01000|00010', '00010|01000',      # family B
        '11000|00011', '00011|11000',      # family E
        '00100|11000', '11000|00100',      # family F
    }
    # agreement families: both accounts favour the same option
    agree_keys = {
        '11111|00000', '00000|11111',      # family D (dominance)
        '00001|00000', '00000|00001',      # family G
        '10000|00000', '00000|10000',      # family H
    }

    def ttb_winner(a, b, order):
        for j in order:
            if a[j] > b[j]:
                return 0
            if b[j] > a[j]:
                return 1
        return -1

    n_conf = 0
    hit_conf = 0
    n_agree = 0
    hit_agree = 0

    for _, row in data.iterrows():
        try:
            a = [int(round(float(x))) for x in row['option_a_ratings']]
            b = [int(round(float(x))) for x in row['option_b_ratings']]
            resp = int(row['response'])
        except Exception:
            continue
        n = len(a)
        if len(b) != n or n == 0:
            continue
        if n == len(validities):
            v = np.asarray(validities, dtype=float)
        else:
            # fallback: assume columns are displayed in ascending validity
            v = np.linspace(0.55, 0.93, n)
        order = list(np.argsort(-v, kind='stable'))
        w = ttb_winner(a, b, order)
        if w < 0:
            continue
        k = key(a) + '|' + key(b)
        if k in conflict_keys:
            n_conf += 1
            hit_conf += 1 if resp == w else 0
        elif k in agree_keys:
            n_agree += 1
            hit_agree += 1 if resp == w else 0

    if n_conf == 0 or n_agree == 0:
        return 0.0

    return float(hit_agree) / n_agree - float(hit_conf) / n_conf

```

**Observed (real) value:** -0.2081 (var=0.0368)
**Predicted under pi_5:** -0.1193 (var=0.0132)
**Predicted under pi_6:** -0.2100 (var=0.0192)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 1]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    # Design validities (display order): col0..col5
    v_default = np.array([0.60, 0.93, 0.55, 0.86, 0.68, 0.78], dtype=float)

    def build(n):
        v = v_default.copy()
        if v.shape[0] < n:
            v = np.concatenate([v, np.full(n - v.shape[0], 0.55)])
        v = v[:n]
        v = np.clip(v, 0.5 + 1e-6, 1 - 1e-6)
        L = np.log(v / (1.0 - v))
        w = np.power(L, 1.5)
        wpos = np.sort(w)[::-1]
        weff = 0.2 * w + 0.8 * wpos          # lam = 0.8, mid of advocated box
        s = weff.sum()
        weff = weff / s if s > 0 else np.ones(n) / n
        cascade = list(np.argsort(-v, kind="stable"))
        return weff, cascade

    cache = {}
    num = 0.0
    den = 0.0

    for a_raw, b_raw, resp in zip(data["option_a_ratings"],
                                  data["option_b_ratings"],
                                  data["response"]):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.shape[0], b.shape[0]))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        if n not in cache:
            cache[n] = build(n)
        weff, cascade = cache[n]

        d = float(np.dot(weff, a - b))

        winner = None
        for j in cascade:
            if a[j] > b[j]:
                winner = 0
                break
            if b[j] > a[j]:
                winner = 1
                break
        if winner is None:
            continue
        if abs(d) < 0.20:                    # ambiguous / near-cancelling for WADD-pos
            continue
        pos_choice = 0 if d > 0 else 1
        if pos_choice == winner:             # models agree -> uninformative
            continue

        den += 1.0
        try:
            r = int(resp)
        except Exception:
            continue
        num += 1.0 if r == pos_choice else 0.0

    if den == 0:
        return 0.5
    return float(num / den)
```

**Observed (real) value:** 0.6587 (var=0.0379)
**Predicted under pi_5:** 0.6767 (var=0.0145)
**Predicted under pi_6:** 0.6307 (var=0.0105)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    def key(x):
        return tuple(int(v) for v in list(x))

    A = [key(x) for x in data['option_a_ratings']]
    B = [key(x) for x in data['option_b_ratings']]
    R = [int(r) for r in data['response']]

    ones5 = (1, 1, 1, 1, 1)
    four = (1, 1, 1, 1, 0)
    zeros = (0, 0, 0, 0, 0)
    weak_single = [(0, 0, 1, 0, 0), (0, 0, 0, 0, 1)]

    hi_n = 0
    hi_d = 0
    lo_n = 0
    lo_d = 0

    for a, b, r in zip(A, B, R):
        if len(a) != 5 or len(b) != 5:
            continue
        # HIGH-coherence cell: 5/5 unanimous panel vs 4/5 panel, differ on cue5 only.
        if a == ones5 and b == four:
            hi_d += 1
            if r == 0:
                hi_n += 1
        elif b == ones5 and a == four:
            hi_d += 1
            if r == 1:
                hi_n += 1
        # LOW-coherence cell: single weak endorsement vs unanimous all-zero panel.
        elif (a in weak_single) and b == zeros:
            lo_d += 1
            if r == 0:
                lo_n += 1
        elif (b in weak_single) and a == zeros:
            lo_d += 1
            if r == 1:
                lo_n += 1

    if hi_d == 0 or lo_d == 0:
        return float('nan')

    p_hi = hi_n / float(hi_d)
    p_lo = lo_n / float(lo_d)
    return float(p_hi - p_lo)

```

**Observed (real) value:** -0.0133 (var=0.0143)
**Predicted under pi_5:** -0.0008 (var=0.0364)
**Predicted under pi_6:** -0.0008 (var=0.0225)

### Experiment 8
**Design**
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[1, 1, 0, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    df = data
    if len(df) == 0:
        return 0.0

    def as_tup(x):
        return tuple(int(v) for v in x)

    A = df['option_a_ratings'].apply(as_tup).values
    B = df['option_b_ratings'].apply(as_tup).values
    R = df['response'].values

    def frac_choose(target, other):
        """Fraction of trials with pair {target, other} on which the
        subject picked `target`. Collapses across A/B display order."""
        num = 0
        den = 0
        for a, b, r in zip(A, B, R):
            if a == target and b == other:
                den += 1
                if int(r) == 0:
                    num += 1
            elif a == other and b == target:
                den += 1
                if int(r) == 1:
                    num += 1
        if den == 0:
            return None
        return float(num) / float(den)

    # ---- cells -------------------------------------------------------
    # Family L (coalition ladder): does the lone top-validity (col2)
    # endorsement keep winning as the opposing coalition grows?
    L1 = frac_choose((0, 0, 1, 0, 0), (1, 0, 0, 0, 0))
    L4 = frac_choose((0, 0, 1, 0, 0), (1, 1, 0, 1, 1))

    # Family U (unanimity step, weighted evidence pinned to col3 only):
    # winner-unanimous cell vs loser-unanimous cell.
    U4 = frac_choose((1, 1, 1, 1, 1), (1, 1, 1, 0, 1))
    U1 = frac_choose((0, 0, 0, 1, 0), (0, 0, 0, 0, 0))

    # Family V (same step at a heavier column, col0).
    V2 = frac_choose((1, 1, 1, 1, 1), (0, 1, 1, 1, 1))
    V1 = frac_choose((1, 0, 0, 0, 0), (0, 0, 0, 0, 0))

    contrasts = []
    if L1 is not None and L4 is not None:
        contrasts.append(L1 - L4)
    if U4 is not None and U1 is not None:
        contrasts.append(U4 - U1)
    if V2 is not None and V1 is not None:
        contrasts.append(V2 - V1)

    if len(contrasts) == 0:
        return 0.0
    return float(np.mean(contrasts))

```

**Observed (real) value:** -0.1500 (var=0.0125)
**Predicted under pi_5:** -0.1183 (var=0.0157)
**Predicted under pi_6:** -0.0475 (var=0.0173)

### Experiment 9
**Design**
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    def key(x):
        try:
            return ''.join([str(int(round(float(v)))) for v in list(x)])
        except Exception:
            return ''

    P_key = frozenset(['01000', '00000'])          # lone strong endorsement vs empty panel
    N_keys = [frozenset(['11111', '10111']),        # unanimous panel vs one dissent (strong cue)
              frozenset(['11111', '11110'])]        # unanimous panel vs one dissent (weak cue)

    p_hits = []
    n_hits = []

    for _, row in data.iterrows():
        ka = key(row['option_a_ratings'])
        kb = key(row['option_b_ratings'])
        if len(ka) == 0 or len(kb) == 0 or ka == kb:
            continue
        pairset = frozenset([ka, kb])
        sa = ka.count('1')
        sb = kb.count('1')
        if sa == sb:
            continue
        try:
            resp = int(row['response'])
        except Exception:
            continue
        # did the subject pick the option carrying the extra endorsement?
        if sa > sb:
            chose_endorsed = 1.0 if resp == 0 else 0.0
        else:
            chose_endorsed = 1.0 if resp == 1 else 0.0

        if pairset == P_key:
            p_hits.append(chose_endorsed)
        else:
            for nk in N_keys:
                if pairset == nk:
                    n_hits.append(chose_endorsed)
                    break

    mp = float(np.mean(p_hits)) if len(p_hits) > 0 else 0.5
    mn = float(np.mean(n_hits)) if len(n_hits) > 0 else 0.5
    return mp - mn

```

**Observed (real) value:** 0.0675 (var=0.0281)
**Predicted under pi_5:** 0.3337 (var=0.0409)
**Predicted under pi_6:** 0.1063 (var=0.0363)

### Experiment 10
**Design**
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = 0
    tot = 0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        try:
            a = [int(x) for x in a_raw]
            b = [int(x) for x in b_raw]
        except Exception:
            continue
        n = min(len(a), len(b))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        a_all = all(x == 1 for x in a)
        b_all = all(x == 1 for x in b)
        # exactly one option must be the unanimous all-ones panel
        if a_all == b_all:
            continue
        other = b if a_all else a
        zeros = [i for i, x in enumerate(other) if x == 0]
        if len(zeros) == 0:
            continue
        # the dissenting (zero) columns must all be WEAK experts:
        # with validities displayed in ascending order, the weak experts
        # occupy the leftmost columns.
        cutoff = max(1, n - 3)
        if any(i >= cutoff for i in zeros):
            continue
        try:
            r = int(resp)
        except Exception:
            continue
        chose_unanimous = (r == 0) if a_all else (r == 1)
        tot += 1
        if chose_unanimous:
            hits += 1
    if tot == 0:
        return 0.5
    return float(hits) / float(tot)
```

**Observed (real) value:** 0.2050 (var=0.0274)
**Predicted under pi_5:** 0.4938 (var=0.0166)
**Predicted under pi_6:** 0.2275 (var=0.0164)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "The single most important fact in the pooled record is one that NEITHER theory anticipated: subjects systematically prefer the panel with FEWER positive endorsements, and they do so with very large magnitude. Experiment 1's metric is (with mirror-collapsing) essentially 'rate of choosing the option with the extra/leading endorsement' in eight cells where the target always carries more 1s; the observed value is 0.135, i.e. subjects picked the sparser panel ~86% of the time, including in the full-dominance cell [111111] vs [000000]. The same signature recurs everywhere: Exp 10 (all-ones vs one weak dissent) = 0.205; Exp 5's agreement family (dominance + lone endorsement vs empty) is far below the conflict family (metric -0.208); Exp 9's two endorsement rates are both low so their difference is ~0.07; Exp 8's contrasts are negative (-0.15); Exp 3's 'TTB adherence' of 0.753 is entirely confounded with 'fewer 1s wins' (every retained conflict trial there has the TTB winner as the sparser panel); Exp 7's hi-lo ~0 follows because both endorsement cells are suppressed equally. Both PWA-DD (pi_5) and ERC-SB (pi_6) contain only a mild endorsement charge (theta calibrated to the weakest cue / to a v* near .85) and therefore predict endorsed options at or above chance; pi_5 predicted 0.74 and pi_6 0.52 on Exp 1 against 0.135 observed. pi_6, whose compressed numerosity charge theta*|m|^zeta is much larger, is closer nearly everywhere the endorsement effect matters (Exp 1: 0.52 vs 0.74; Exp 9: 0.11 vs 0.33; Exp 10: 0.23 vs 0.49; Exp 5: -0.21 vs -0.12) and only loses on Exp 2 (-0.227 vs observed -0.004, where pi_5's +0.078 is closer) and Exp 8. Summed absolute error is ~0.83 for pi_6 versus ~1.41 for pi_5, so pi_5 is the weaker, more dispensable theory. A second cross-experiment fact is also unexplained by both: positional (left-to-right) reading appears to dominate even when the display IS validity-monotone. Exp 5 shows ascending-validity displays (best expert rightmost) with sub-chance TTB adherence in count-matched conflicts, and Exp 6 (scrambled) shows 0.66 adherence to the positional weighting; both theories' readability gates are inert for any monotone display and therefore predict validity-driven behaviour there. Neither theory is task-invariant: pi_5 fails the endorsement-aversion family badly, and pi_6, while better, still misses Exp 1 by ~0.39 and over-predicts contrast-count compression in Exp 2. Rather than re-tuning pi_5's parameters, the field needs a theory whose primary driver is endorsement-count aversion, with a position-dominated tiebreak.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace pi_5 (PWA-DD) with a theory built around the two facts both current theories miss.\n\nSketch \"LPS-ECA: Left-to-Right Primacy Scanning with Endorsement-Count Aversion\".\n(1) PRIMARY DRIVER \\u2014 numerosity aversion. Each displayed '1' carries a credibility/effort cost c that EXCEEDS the diagnostic weight of every single expert (c > max_j w_j), so whenever the two panels differ in total endorsement count the sparser panel is chosen with high probability, essentially independently of which experts endorsed. The cost is levied on a compressed count surplus, cost = c*sign(m)*|m|^zeta with zeta<1, so 6-vs-0 (dominance) is only modestly more decisive than 1-vs-0. Target cell values: lone endorsement vs empty ~0.15\\u20130.25 for the endorsed panel (roughly flat across the endorsing expert's validity, Exp 1 V-family and Exp 5/8/9 lone-cue cells), full dominance ~0.10\\u20130.20 for the all-ones panel (Exp 1 D, Exp 5, Exp 10), unanimous-vs-one-dissent ~0.20 (Exp 10 = 0.205).\n(2) SECONDARY DRIVER \\u2014 count-matched trials are decided by a weighted column difference in which the LEFT-TO-RIGHT PRIMACY GRADIENT dominates and stated validity contributes only weakly, REGARDLESS of whether the display is validity-monotone. This is the sharp break from both PWA-DD and ERC-SB, whose gates make position inert for sorted displays. It must reproduce: descending display (Exp 3, Exp 1/2) \\u2192 leftmost/most-valid option wins count-matched contrasts ~0.65\\u20130.75; ascending display (Exp 5) \\u2192 sub-chance TTB adherence in count-matched conflicts (~0.30\\u20130.45), because leftmost is now the LEAST valid; scrambled displays (Exp 4, Exp 6) \\u2192 positional weighting adherence ~0.6\\u20130.7 and near-chance TTB adherence (~0.51).\n(3) NO contrast-count (K) normalisation and NO density normalisation: sensitivity should be roughly constant across K and across shared endorsement background, since Exp 2's near-zero metric penalises pi_6's steep K-compression while Exp 1's uniformly low target rate gives no evidence for density dilution over and above the count cost.\n(4) Determinacy: moderate beta plus a modest lapse so that the extreme cells land near 0.15\\u20130.20 rather than 0.02, and so between-subject variance is ~0.005\\u20130.03 as observed.\nQuantitative acceptance targets for the new theory: Exp1 \\u2248 0.14, Exp2 \\u2248 0.00, Exp3 \\u2248 0.75, Exp4 \\u2248 0.51, Exp5 \\u2248 -0.21, Exp6 \\u2248 0.66, Exp7 \\u2248 -0.01, Exp8 \\u2248 -0.15, Exp9 \\u2248 0.07, Exp10 \\u2248 0.21. This makes it a strictly stronger competitor to ERC-SB (which it beats on Exp 1, 2, 6, 8) while remaining mechanistically distinct (numerosity cost that outweighs all cue weights + always-on positional primacy, versus expectation-referenced per-cue coding + binding-conditional K normalisation)."
}
```

## Usage

```json
{
  "input_tokens": 34086,
  "output_tokens": 14158
}
```
