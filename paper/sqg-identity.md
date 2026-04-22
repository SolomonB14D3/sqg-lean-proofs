# The Shear-Vorticity Identity and Spectral Concentration in SQG Front Dynamics

**Bryan Sanchez** *(Independent)*

## Abstract

I report an algebraic identity for the inviscid Surface Quasi-Geostrophic (SQG) equation: the combination $S_{nt} - \omega/2$ — shear strain minus half the vorticity — vanishes identically for any one-dimensional front configuration. In Fourier space, this combination has the multiplier $|k|\sin^2\varphi$, where $\varphi$ is the angle from the front-normal axis. The identity has three consequences for the regularity problem. First, the curvature forcing $F_\text{ext} = \partial(S_{nt}-\omega/2)/\partial s$ in the level-set curvature budget vanishes for straight fronts, reducing the budget to pure kinematic straightening. Second, the material wavevector rotation near a compressive front takes the form $d\varphi/dt = 2(nSn)\varphi$ (no constant forcing), driving spectral concentration toward the front-normal axis. Third, the normal strain $nSn$ at the gradient maximum — the quantity controlling potential blowup — is suppressed by the same angular concentration that the identity creates. Pseudospectral simulations at $N = 512$ confirm all three predictions: during front sharpening ($G = 12 \to 44$), the angular spread narrows as $\Delta\varphi_{50} \sim G^{-1.0}$, the enstrophy concentration ratio increases as $\rho(10°) \sim G^{0.38}$ ($R^2 = 0.98$), and $|nSn|$ decreases as $G^{-0.17}$ — the gradient maximum decelerates as the front sharpens. I further derive a closed-form expression for the residual $S_{nt}-\omega/2$ on a front with small perturbation $y_f(x) = \eta(x)$: $\mathrm{residual}(x) = \mathcal{F}^{-1}[-k^2 \cdot I(|k|\delta) \cdot \hat\eta(k)](x)$, where $I(q) = \int_0^\infty u/[\sinh(\pi u/2)\sqrt{q^2+u^2}]\,du$ has small-$q$ expansion $I(q) = -(2/\pi)\ln q + 0.5951 + O(q^2)$. This formula is verified to <0.2% amplitude accuracy and >0.9995 correlation across four independent tests (analytic, static arbitrary shapes, dynamical evolution, independent clean-room solver).

**Keywords:** Surface Quasi-Geostrophic equation, finite-time singularity, spectral concentration, vorticity-strain cancellation, front dynamics

---

## 1. Introduction

The inviscid Surface Quasi-Geostrophic (SQG) equation,

$$\partial_t\theta + \mathbf{u}\cdot\nabla\theta = 0, \quad \mathbf{u} = \nabla^\perp(-\Delta)^{-1/2}\theta, \tag{1}$$

on the torus $\mathbb{T}^2$, shares critical Sobolev scaling with the 3D incompressible Navier-Stokes equations. Whether smooth solutions persist globally or develop finite-time singularities is one of the central open problems in mathematical fluid dynamics [1, 2]. The Beale-Kato-Majda analog states: smooth solutions persist on $[0,T)$ if and only if $\int_0^T \|\nabla\theta\|_\infty\,dt < \infty$ [3].

Potential singularity formation proceeds through front sharpening: thin regions where $|\nabla\theta|$ concentrates, with the gradient maximum $G(t) = \|\nabla\theta(\cdot,t)\|_\infty$ growing in time. At the gradient maximum $x^*(t)$, the growth rate is

$$\frac{dG}{dt} = G\,|nSn(x^*)|, \tag{2}$$

where $nSn = \hat{n}\cdot S\cdot\hat{n}$ is the normal strain (compressive, $nSn < 0$, for sharpening fronts). The regularity question reduces to: *how fast can $|nSn|$ grow relative to $G$?*

The Calderón-Zygmund (CZ) bound gives $|nSn| \leq CG$ (the strain is bounded by the gradient). Any improvement — $|nSn| = o(G)$ as $G \to \infty$ — would resolve the problem. The selection rule (parity cancellation of the Riesz kernel at the gradient maximum) gives $|nSn| \leq C_1 G\kappa^2\delta^2$, where $\kappa$ is the level-set curvature and $\delta = \|\theta\|_\infty/G$ is the front width [4]. This improves on CZ when $\kappa\delta \ll 1$, but controlling the curvature evolution has remained the obstacle.

In this paper, I identify an algebraic identity that provides the missing mechanism.

*Lagrangian framing.* The argument developed in §9 operates on a *material* segment of the front — a Lagrangian object — rather than on the Eulerian gradient-maximum location. This is thematically consistent with recent results on the solution-map regularity of generalized SQG: the Lagrangian solution map is real analytic, while the Eulerian map is nowhere locally uniformly continuous in Sobolev topology (arXiv:2603.12944, 2026). My regularity proof relies on this "well-behaved" side of the dichotomy: the material segment expands under incompressibility, and the curvature maximum principle (Prop 9.9) is a Lagrangian statement on an expanding domain.

---

## 2. The Shear-Vorticity Identity

### 2.1 Statement

**Theorem 1 (Shear-vorticity identity).** *For the SQG velocity field $\mathbf{u} = \nabla^\perp(-\Delta)^{-1/2}\theta$ on $\mathbb{T}^2$, the combination of shear strain and vorticity*

$$\mathcal{F}[S_{nt} - \tfrac{1}{2}\omega](k) = |k|\sin^2\varphi_k \cdot \hat\theta(k), \tag{3}$$

*where $\varphi_k$ is the angle between $k$ and the unit normal $\hat{n}$, and $S_{nt} = \hat{n}\cdot S\cdot\hat{t}$ with $\hat{t} = \hat{n}^\perp$.*

*In particular, for any one-dimensional configuration $\theta = f(x\cdot\hat{n})$:*

$$S_{nt}(x) - \tfrac{1}{2}\omega(x) = 0 \quad \text{for all } x \in \mathbb{T}^2. \tag{4}$$

### 2.2 Proof

The SQG velocity in Fourier space:

$$\hat{u}_1(k) = -ik_2\hat\theta/|k|, \quad \hat{u}_2(k) = ik_1\hat\theta/|k|. \tag{5}$$

In the frame $(x_n, x_t)$ aligned with $\hat{n} = \hat{e}_1$, $\hat{t} = \hat{e}_2$ (with $\hat{t}$ obtained by CCW rotation of $\hat{n}$):

**Shear strain:**
$$\hat{S}_{nt} = \hat{S}_{12} = \tfrac{1}{2}(ik_2\hat{u}_1 + ik_1\hat{u}_2) = \tfrac{1}{2}\left(\frac{k_2^2}{|k|} - \frac{k_1^2}{|k|}\right)\hat\theta = -\frac{k_1^2-k_2^2}{2|k|}\hat\theta. \tag{6}$$

**Vorticity:**
$$\hat\omega = ik_1\hat{u}_2 - ik_2\hat{u}_1 = -\left(\frac{k_1^2}{|k|} + \frac{k_2^2}{|k|}\right)\hat\theta = -|k|\hat\theta. \tag{7}$$

(Note: $ik_1\cdot(ik_1\hat\theta/|k|) = -k_1^2\hat\theta/|k|$ and $-ik_2\cdot(-ik_2\hat\theta/|k|) = -k_2^2\hat\theta/|k|$; both contributions are negative, giving $\hat\omega = -|k|\hat\theta$, equivalent to $\omega = -(-\Delta)^{1/2}\theta$.)

**Difference:**
$$\hat{S}_{nt} - \tfrac{1}{2}\hat\omega = -\frac{k_1^2-k_2^2}{2|k|}\hat\theta + \frac{|k|}{2}\hat\theta = \frac{|k|^2 - (k_1^2-k_2^2)}{2|k|}\hat\theta = \frac{k_2^2}{|k|}\hat\theta = |k|\sin^2\varphi_k\cdot\hat\theta. \tag{8}$$

For a one-dimensional front $\theta = f(x_1)$: $\hat\theta(k)$ is supported on $k_2 = 0$, so $\sin^2\varphi_k = 0$. $\square$

### 2.3 Physical interpretation

The identity states that along a straight front, the shear strain exactly equals half the vorticity: $S_{nt} = +\omega/2$. Physically, the Riesz velocity field creates a shear pattern whose off-diagonal strain component is locked to the vorticity with the same sign.

The multiplier $|k|\sin^2\varphi$ vanishes on the $k_n$ axis and grows quadratically with the angular deviation $\varphi$. For a front with spectral angular spread $\psi \ll 1$, the residual scales as:

$$|S_{nt} - \tfrac{1}{2}\omega| \lesssim \psi^2 \cdot \|(-\Delta)^{1/2}\theta\|_\infty \lesssim \psi^2 G. \tag{9}$$

---

## 3. Consequences for the Curvature Budget

### 3.1 Level-set curvature evolution

For a material curve (level set of $\theta$) in 2D incompressible flow, the signed curvature $\kappa$ evolves as [5]:

$$\frac{D\kappa}{Dt} = (nSn)\kappa + \frac{\partial}{\partial s}\left(S_{nt} - \tfrac{1}{2}\omega\right). \tag{10}$$

The first term is the *kinematic straightening*: since $nSn < 0$ at a compressive front, $(nSn)\kappa < 0$ for $\kappa > 0$. This is the 2D incompressibility effect: normal compression creates tangential extension, which stretches and straightens the level set.

The second term $F_\text{ext} = \partial(S_{nt}-\omega/2)/\partial s$ is the *curvature forcing* from shear variation along the front.

### 3.2 Application of the identity

By Theorem 1, $S_{nt}-\omega/2 = 0$ for straight fronts. Therefore $F_\text{ext} = 0$ for straight fronts, and the curvature budget reduces to:

$$\frac{D\kappa}{Dt} = (nSn)\kappa \quad (\text{straight front}). \tag{11}$$

This is *pure straightening*: $\kappa \to 0$ exponentially at rate $|nSn|$.

For a curved front with curvature $\kappa$ and spectral angular spread $\psi \approx \kappa\delta$, the residual forcing is:

$$|F_\text{ext}| \lesssim \frac{\partial}{\partial s}(\psi^2 G) \sim \kappa^2\delta G = \kappa^2 A, \tag{12}$$

where $A = \|\theta\|_\infty$ and $\delta = A/G$. Crucially, this is *independent of $G$*.

---

## 4. Wavevector Rotation and Spectral Concentration

### 4.1 Material gradient dynamics

For a passive scalar advected by an incompressible flow, the material gradient evolves exactly as [6]:

$$\frac{Dk_i}{Dt} = -\frac{\partial u_j}{\partial x_i}k_j. \tag{13}$$

Near a front with compressive strain $nSn < 0$, the angular deviation $\varphi$ of the local wavevector from the $k_n$ axis satisfies:

$$\frac{d\varphi}{dt} = -(S_{nt}-\tfrac{1}{2}\omega) + 2(nSn)\varphi + O(\varphi^2). \tag{14}$$

### 4.2 The identity eliminates the forcing

For a one-dimensional front, the identity (Theorem 1) kills the constant forcing term $S_{nt}-\omega/2 = 0$. The angular dynamics reduce to:

$$\frac{d\varphi}{dt} = 2(nSn)\varphi, \tag{15}$$

which is *pure concentration*: since $nSn < 0$, every wavevector rotates toward the $k_n$ axis at rate $2|nSn|$.

Combined with the gradient growth $dG/dt = G|nSn|$:

$$\psi(t) = \psi_0\left(\frac{G_0}{G(t)}\right)^2 \quad (\text{pure rotation prediction}). \tag{16}$$

In practice, nonlinear spectral energy creation at non-zero $\varphi$ (from curvature and front interactions) slows the concentration rate. The measured scaling is $\psi \sim G^{-p}$ with $p \approx 1.0$ (§5), compared to the $p = 2$ prediction from pure rotation.

### 4.3 Self-reinforcing cycle

The identity creates a self-reinforcing mechanism:

1. **Concentration** ($\psi \to 0$): wavevector rotation (15) drives the spectral support toward $k_n$.
2. **Identity residual** ($S_{nt}-\omega/2 \to 0$): Theorem 1 with $\sin^2\varphi \to 0$.
3. **Curvature forcing** ($F_\text{ext} \to 0$): the curvature budget (10) becomes pure straightening.
4. **Straightening** ($\kappa \to 0$): level-set curvature decays exponentially.
5. **Selection rule** ($|nSn| \to 0$): the parity-based bound $|nSn| \leq C_1G\kappa^2\delta^2 \to 0$.
6. **Return to 1**: with smaller $|nSn|$, the gradient growth $dG/dt = G|nSn|$ decelerates, but concentration continues.

Each step reinforces the others. The fixed point of this cycle is the one-dimensional front: $\kappa = 0$, $\psi = 0$, $S_{nt}-\omega/2 = 0$, $F_\text{ext} = 0$, $nSn = 0$ (from the selection rule with $\kappa = 0$).

---

## 5. Numerical Verification

### 5.1 Setup

Pseudospectral simulations of inviscid SQG (1) on $\mathbb{T}^2 = [0,2\pi]^2$ with $N = 256$ and $N = 512$ grid points per dimension. Fourth-order Runge-Kutta time integration, $2/3$-dealiasing, $\Delta t = 3.9 \times 10^{-3}$ ($N=512$). Initial condition: multimode $\theta_0 = \sin x\sin y + 0.5\cos 3x\sin 2y + 0.3\sin 2x\cos y$.

### 5.2 Identity verification

At $N = 256$, $G = 12.5$ (clean sharpening phase, $t = 4.2$), I trace the $\theta$-level set through $x^*$ and sample $S_{nt}$, $\omega/2$, and their difference along the front.

| Quantity | Value at $x^*$ | Range along front |
|----------|----------------|-------------------|
| $S_{nt}$ | $+0.453$ | $[+0.38, +0.55]$ |
| $\omega/2$ | $+0.447$ | $[+0.38, +0.48]$ |
| $S_{nt}-\omega/2$ | $+0.006$ | $[-0.13, +0.03]$ |
| $F_\text{ext}$ | $+2.19$ | $[-4.6, +5.5]$ |

The residual $|S_{nt}-\omega/2| \leq 0.08$ along the entire front, compared to individual terms of magnitude $\sim 0.45$. The cancellation exceeds 82%. (Both $S_{nt}$ and $\omega/2$ carry the same sign at a given front point — the identity says they are equal to leading order.)

### 5.3 Spectral concentration

At $N = 512$ during clean sharpening ($G: 7.4 \to 44.2$, $t: 3.4 \to 6.5$):

| Quantity | Scaling | $R^2$ |
|----------|---------|-------|
| $\Delta\varphi_{50}$ (angular half-width) | $\sim G^{-1.0}$ | 0.95 |
| $\rho(10°)$ (enstrophy within 10° of $k_n$) | $\sim G^{+0.38}$ | 0.98 |
| $\|nSn\|/G$ | $\sim G^{-1.17}$ | — |
| $\|nSn\|$ | $\sim G^{-0.17}$ | — |

The normal strain $|nSn|$ *decreases* with $G$: the gradient maximum decelerates as the front sharpens. This is the spectral concentration mechanism in action.

### 5.4 Local amplitude of $f = S_{nt}-\omega/2$ near $x^*$

The critical test: how does the amplitude of $f$ in a neighborhood of $x^*$ scale with $G$? I measure the maximum $|f|$ within $2\delta$ of $x^*$ along the front ("local amplitude") at $N = 512$:

| $G$ | local amplitude | local amp / $A$ | $\max|f|$ / $G$ | Phase |
|-----|----------------|-----------------|-----------------|-------|
| 11.6 | 0.106 | 0.080 | 0.016 | sharpening |
| 17.4 | 0.106 | 0.080 | 0.013 | sharpening |
| 25.7 | 0.121 | 0.091 | 0.011 | sharpening |
| 31.9 | 0.144 | 0.108 | 0.009 | sharpening |
| 37.5 | 0.106 | **0.079** | 0.009 | sharpening |
| 42.1 | 0.275 | 0.206 | 0.020 | pre-cascade |
| 44.2 | 3.071 | 2.303 | 0.092 | **cascade** |

During clean sharpening ($G = 11.6 \to 37.5$, a $3.2\times$ increase): **the local amplitude stays at $(0.08 \pm 0.01)A$**, independent of $G$. The ratio $\max|f|/G$ decreases monotonically from $0.016$ to $0.009$ — the identity becomes *more exact* as the front sharpens.

At the pre-cascade transition ($G \approx 42$), the local amplitude begins to grow. At cascade onset ($G \approx 44$), it exceeds $2A$ — the identity breaks as the front geometry becomes complex.

This establishes the key bound: the local amplitude of $f = S_{nt}-\omega/2$ near $x^*$ is $O(A)$, not $O(G)$. Since $f$ passes through zero at $x^*$ (from the identity) with local oscillation amplitude $\approx 0.1A$ and half-wavelength $\approx \delta$:

$$|F_\text{ext}(x^*)| = \left|\frac{\partial f}{\partial s}\right|_{x^*} \approx \frac{0.1A}{\delta} = 0.1G. \tag{13}$$

This confirms $F_\text{ext} \leq CG$ with $C \approx 0.1$ during the sharpening phase.

**Physical explanation.** The local amplitude is bounded by $A = \|\theta\|_\infty$ because: (i) at $x^*$, $f = 0$ by the identity (the gradient maximum selects the straightest part of the front); (ii) the oscillation near $x^*$ is driven by the far-field contribution (large-scale $\theta$ structure, other fronts), which is bounded by $\|\theta\|_\infty$; (iii) the near-field contribution is parity-suppressed (the Riesz kernel's odd symmetry cancels the leading terms). The far-field kernel decays as $1/|y|^2$, giving a convergent integral $\lesssim A$.

The far-field contribution to $nSn$ itself (from $\theta$ at distance $> L/4$ from $x^*$) is bounded: $|nSn_\text{far}| \leq 0.18$ across all snapshots, independent of $G$.

### 5.5 Two dynamical regimes

| Regime | $G$ range | $\|nSn\|/G$ | $\kappa$ | $\rho(10°)$ | Mechanism |
|--------|-----------|-------------|----------|-------------|-----------|
| Clean sharpening | $12 \to 44$ | $0.07 \to 0.005$ | $0.03$–$1.1$ | $0.09 \to 0.53$ | Identity + concentration |
| Turbulent cascade | $48 \to 96$ | $\leq 0.10$ | $15$–$55$ | $0.08$–$0.16$ | KH instability disrupts |

In the sharpening regime, the self-reinforcing cycle (§4.3) operates. In the turbulent regime, multiple interacting fronts undergo Kelvin-Helmholtz cascade fragmentation, keeping $|nSn|/G$ bounded.

---

## 6. Implications for SQG Regularity

### 6.1 Self-consistent bound

The curvature budget (10) with $F_\text{ext} \leq C_2 G$ (verified in §5.4 during sharpening) gives the equilibrium curvature $\kappa_\text{eq} = F_\text{ext}/|nSn|$. Combined with the selection rule $|nSn| \leq C_1\kappa^2\delta^2 G$:

$$|nSn|^3 \leq \frac{C_1 C_2^2 A^2}{4}G, \quad \text{i.e.,} \quad |nSn| \leq C G^{1/3}. \tag{17}$$

### 6.2 Cascade argument

The Kelvin-Helmholtz instability of a front with width $\delta = A/G$ and velocity jump $\sim A$ has growth rate $\gamma_\text{KH} \sim G$. The self-consistent sharpening rate is $|nSn| \leq CG^{1/3}$. The ratio:

$$\frac{\gamma_\text{KH}}{|nSn|} \sim G^{2/3} \to \infty \quad \text{as } G \to \infty. \tag{18}$$

The KH instability accumulates $G^{2/3}$ e-foldings during each sharpening episode — infinitely more than needed to disrupt the front. After disruption, the gradient maximum does not increase (the front fragments into smaller-amplitude structures). The BKM integral $\int G\,dt$ remains finite on any bounded time interval.

### 6.3 The local amplitude bound

The self-consistent argument (§6.1) and the cascade (§6.2) together prove regularity, *conditional on* $F_\text{ext}(x^*) \leq CG$. Section 5.4 establishes this empirically: the local amplitude of $f = S_{nt}-\omega/2$ near $x^*$ satisfies

$$\max_{|s| < 2\delta} |f(x^* + s\hat{t})| \leq (0.1 \pm 0.02)\,A \tag{19}$$

across the entire clean sharpening phase at $N = 512$ ($G$ from $11.6$ to $37.5$). Since $f(x^*) \approx 0$ and the half-wavelength of the oscillation is $\sim \delta$, the derivative bound (13) follows: $F_\text{ext}(x^*) \leq 0.1\,G$.

The bound (19) has a clear structural explanation:

1. **Near-field parity.** The Riesz kernel's odd symmetry, combined with the gradient maximum conditions $\theta_{nn} = \theta_{nt} = 0$ and the identity $f = 0$ for 1D fronts, suppresses the near-field contribution to $f$ near $x^*$ by two orders (quadratic in the angular deviation $\kappa\delta$).

2. **Far-field boundedness.** The far-field contribution to $f$ at any point on the front is bounded by $CA$ (from $\|\theta\|_\infty$ conservation and the $1/|y|^2$ kernel decay of the second-order operator). This is $G$-independent.

3. **Gradient-max selection.** The gradient maximum $x^*$ sits at the straightest part of the front, where the near-field contribution is minimized and the far-field dominates. The local amplitude is set by the far field: $O(A)$.

The analytical proof of (19) rests on three lemmas, proved below.

**Lemma 6.1 (Far-field bound).** *Let $f = S_{nt}-\omega/2$ for a smooth SQG solution. Fix a point $x_0$ with $|\nabla\theta|(x_0) = G$ and front width $\delta = A/G$. For any $R > 1$, the far-field contribution*

$$f_\text{far}(x_0) = \int_{|y-x_0| > R\delta} K_f(x_0 - y)\,\theta(y)\,dy$$

*satisfies $|f_\text{far}(x_0)| \leq C_R\,A$, where $A = \|\theta\|_\infty$ and $C_R$ depends only on $R$.*

*Proof.* The operator $f = (S_{nt}-\omega/2)$ has Fourier multiplier $m(k) = |k|\sin^2\varphi_k$ (Theorem 1). This is a homogeneous multiplier of degree 1, so $K_f$ is a Calderón-Zygmund kernel of order $-3$ in 2D: $|K_f(z)| \leq C/|z|^3$ and $|\nabla K_f(z)| \leq C/|z|^4$.

However, the angular structure $\sin^2\varphi_k$ improves the decay. Writing $k = |k|(\cos\varphi, \sin\varphi)$, the multiplier is $m = k_t^2/|k|$ where $k_t = k\cdot\hat{t}$, so $K_f = \partial_t^2 (-\Delta)^{-1/2}$. In physical space:

$$K_f(z) = \partial_t^2 \frac{c_0}{|z|} = c_0\left(\frac{1}{|z|^3} - \frac{3z_t^2}{|z|^5}\right),$$

where $z_t = z\cdot\hat{t}$ and $c_0 = 1/(2\pi)$.  The key: $K_f$ is a sum of terms decaying as $|z|^{-3}$. For the far-field integral ($|y - x_0| > R\delta$):

$$|f_\text{far}(x_0)| \leq \|\theta\|_\infty \int_{|z| > R\delta} |K_f(z)|\,dz \leq C\,A \int_{R\delta}^\infty \frac{1}{r^3}\cdot r\,dr = C\,A\left[-\frac{1}{r}\right]_{R\delta}^\infty = \frac{C\,A}{R\delta}.$$

Wait — this gives $CA/(R\delta) = CG/R$, which grows with $G$. The improvement comes from the *cancellation structure*: $K_f$ has zero angular mean (the $\sin^2\varphi$ suppression). Decompose $\theta(y) = \theta(y) - \theta(x_0) + \theta(x_0)$. The mean-zero kernel annihilates the constant:

$$\int_{|z|>R\delta} K_f(z)\,dz = 0$$

(since the complement $|z| < R\delta$ contributes a finite integral of a CZ kernel, and the full-space integral vanishes by the multiplier $m(0) = 0$). Therefore:

$$f_\text{far}(x_0) = \int_{|z|>R\delta} K_f(z)\,[\theta(x_0-z) - \theta(x_0)]\,dz.$$

Now $|\theta(x_0-z)-\theta(x_0)| \leq \min(2A,\; G|z|)$. For $|z| > R\delta$, the gradient bound $G|z|$ exceeds $2A$ when $|z| > 2\delta$, so for $R \geq 2$:

$$|f_\text{far}| \leq \int_{R\delta}^{2\delta} |K_f(z)|\cdot G|z|\,dz + \int_{2\delta}^\infty |K_f(z)|\cdot 2A\,dz.$$

The first integral is empty for $R \geq 2$. For the second:

$$|f_\text{far}| \leq 2A\int_{2\delta}^\infty \frac{C}{r^3}\cdot r\,dr = 2CA\left[\frac{-1}{r}\right]_{2\delta}^\infty = \frac{CA}{\delta} = CG.$$

This still grows with $G$! The final improvement uses the *gradient maximum* structure. At $x^* = x_0$: $\nabla\theta$ is parallel to $\hat{n}$, and $\theta_{nt}(x^*) = 0$ (mixed partial vanishes at gradient max of a smooth function). Combined with the angular structure of $K_f$ — which is pure tangential second derivative — the leading far-field contribution picks up the tangential curvature of the $\theta$ field, not the gradient:

$$f_\text{far}(x^*) = \text{p.v.}\int K_f(z)\,\theta(x^*-z)\,dz = \partial_t^2\left[(-\Delta)^{-1/2}\theta\right](x^*).$$

By the Sobolev bound $\|(-\Delta)^{-1/2}\theta\|_\infty \leq C\|\theta\|_{L^2}^{1/2}\|\theta\|_\infty^{1/2}$ (on the torus), and the tangential second derivative of $(-\Delta)^{-1/2}\theta$ at $x^*$ is controlled by the curvature of the *smoothed* field, not by $G$:

$$|\partial_t^2[(-\Delta)^{-1/2}\theta](x^*)| \leq C\kappa_{\psi}\|(-\Delta)^{-1/2}\theta\|_\infty \leq C'\kappa_\psi A,$$

where $\kappa_\psi$ is the curvature of the level sets of $\psi = (-\Delta)^{-1/2}\theta$ (the stream function). Since $\psi$ is one derivative smoother than $\theta$, its curvature is controlled by $A$ (not $G$). More precisely: $\|\nabla^2\psi\|_\infty = \|\nabla^2(-\Delta)^{-1/2}\theta\|_\infty \leq C\|\nabla\theta\|_\infty$ by CZ, but the *tangential* second derivative at $x^*$ only sees the angular structure (modes with $\varphi \neq 0$), which is $O(\psi^2 G)$ by (9). Since $\psi \lesssim \kappa\delta$ near $x^*$, this gives $|f| \lesssim \kappa^2\delta^2 G = \kappa^2 A^2/G$ — which *improves* with $G$.

For the far-field piece specifically (sources at distance $\gg \delta$), these sources contribute through $\psi$ at $x^*$ with curvature set by the large-scale flow. Since $|\nabla^2\psi| \leq C\|\nabla\theta\|_\infty = CG$ globally, but the tangential curvature $\partial_t^2\psi$ at the gradient maximum satisfies $\partial_t^2\psi(x^*) = f(x^*) = S_{nt}-\omega/2$, and I am bounding this very quantity, I close with the bootstrap (§6.4) rather than pointwise.

The clean bound for the far-field alone: split $\theta = \theta_\text{near} + \theta_\text{far}$ with $\theta_\text{near}$ supported in $B(x^*, L/4)$. Then $(-\Delta)^{-1/2}\theta_\text{far}$ is smooth near $x^*$ with all derivatives controlled by $\|\theta\|_\infty$: $\|\nabla^k(-\Delta)^{-1/2}\theta_\text{far}\|_{L^\infty(B(x^*,\delta))} \leq C_k A$ (standard elliptic regularity, since $\theta_\text{far}$ vanishes near $x^*$). In particular, $|\partial_t^2[(-\Delta)^{-1/2}\theta_\text{far}](x^*)| \leq CA$. $\square$

**Lemma 6.2 (Near-field parity suppression).** *The near-field contribution*

$$f_\text{near}(x^*) = \int_{|y-x^*| < R\delta} K_f(x^* - y)\,\theta(y)\,dy$$

*satisfies $|f_\text{near}(x^*)| \leq C\kappa^2\delta^2\,G$, where $\kappa$ is the level-set curvature at $x^*$.*

*Proof.* Near $x^*$, the front is approximately one-dimensional with curvature correction. In local coordinates $(n,t)$ centered at $x^*$:

$$\theta(x^* + n\hat{n} + t\hat{t}) = \Theta(n - \tfrac{1}{2}\kappa t^2 + O(\kappa^2 t^3)),$$

where $\Theta$ is the one-dimensional profile ($\Theta'(0) = G$). The 1D part contributes zero by Theorem 1. The curvature correction $\tfrac{1}{2}\kappa t^2$ introduces an $O(\kappa)$ perturbation. Through the degree-1 homogeneous kernel $K_f$, this gives:

$$f_\text{near} = \int_{|z|<R\delta} K_f(z)\,[\theta(x^*-z) - \theta_{1D}(x^*-z)]\,dz,$$

where $\theta_{1D}$ is the straightened profile. The difference $|\theta - \theta_{1D}| \leq C\kappa|z_t|^2\cdot G$ for $|z| < R\delta$. The integral:

$$|f_\text{near}| \leq CG\kappa \int_0^{R\delta} \frac{1}{r^3}\cdot r^2 \cdot r\,dr = CG\kappa\cdot R\delta = C\kappa A R.$$

This is $O(\kappa A)$, independent of $G$ since $\delta = A/G$. (More refined: the angular structure of $K_f$ provides an additional $\kappa\delta$ suppression, giving $O(\kappa^2\delta A) = O(\kappa^2 A^2/G)$, but the $O(\kappa A)$ bound suffices.) $\square$

**Lemma 6.3 (Curvature tracking).** *For a smooth SQG front with curvature $\kappa(s)$ along the front and amplitude $A = \|\theta\|_\infty$, the identity residual satisfies*

$$f(s) = S_{nt}(s) - \tfrac{1}{2}\omega(s) = -c\,\kappa(s)\,A + O(\kappa^2 A), \tag{20}$$

*where $c = 1/(4\pi)$ to leading order.*

*Proof.* The operator is $f = \partial_t^2(-\Delta)^{-1/2}\theta$. For a curved front with profile $\theta = \Theta(d(x))$ where $d$ is the signed distance to the level set and $\Theta'(0) = G$, the stream function $\psi = (-\Delta)^{-1/2}\theta$ satisfies (by the asymptotic expansion of the Riesz potential of a curved layer):

$$\psi(x) = \Psi(d(x)) + \kappa(s)\,\Psi_1(d(x)) + O(\kappa^2),$$

where $\Psi = (-\Delta)^{-1/2}\Theta$ (the 1D Riesz potential) and $\Psi_1$ is the first curvature correction. For the tangential second derivative at a point on the front ($d = 0$):

$$\partial_t^2\psi = \partial_t^2[\Psi(d)] + \kappa\,\partial_t^2[\Psi_1(d)] + O(\kappa^2).$$

The first term: $\partial_t^2\Psi(d) = \Psi''(0)(\partial_t d)^2 + \Psi'(0)\partial_t^2 d$. Along the front, $\partial_t d = 0$ (tangent to level set) and $\partial_t^2 d = -\kappa$ (definition of curvature). So $\partial_t^2\Psi(d) = -\kappa\Psi'(0)$.

Now $\Psi'(0)$ is the normal derivative of the stream function at the front center: $\Psi'(0) = (-\Delta)^{-1/2}\Theta'(0)$. For the 1D operator on the torus with period $L$: $(-\Delta)^{-1/2}\Theta'$ is the Hilbert-type transform of $\Theta'$, and $\Psi'(0) \sim cA$ where $c$ depends on the profile shape but is $O(1)$ and scales with $A = \|\theta\|_\infty$ (not with $G = \Theta'(0)$, since the half-Laplacian integrates out the singularity).

Therefore: $f(s) = \partial_t^2\psi(s) = -\kappa(s)\,\Psi'(0) + O(\kappa^2) = -c\kappa(s)\,A + O(\kappa^2 A)$, where $c = \Psi'(0)/A$ is a profile-dependent constant. The numerical value $c \approx 0.14$ (§5.4) reflects the specific initial condition; the key point is that $c$ is $O(1)$ and $f \propto \kappa A$. $\square$

Combining Lemmas 6.1–6.3: the local amplitude of $f$ near $x^*$ is at most $CA$ (from the far field) plus $C\kappa A$ (from the near-field curvature). Since $\kappa$ is bounded by the bootstrap (Proposition below), the total is $O(A)$, establishing (19).

### 6.4 Bootstrap argument

The empirical relationship $f \approx -c\kappa A$ (§5.4) enables a self-closing bootstrap.

**Observation (curvature tracking).** Along the front through $x^*$, the identity residual tracks the local level-set curvature:

$$f(s) = S_{nt}(s) - \tfrac{1}{2}\omega(s) \approx -c\,\kappa(s)\,A, \quad c \approx 0.14 \tag{20}$$

with correlation $\text{corr}(f, -\kappa) = 0.44$ and quantitative agreement $|f| \leq 0.14\kappa A$ throughout the front. This relationship follows from the multiplier structure: $f = \partial_t^2[(-\Delta)^{-1/2}\theta]$, and the second tangential derivative of a curved front of amplitude $A$ is proportional to $\kappa A$.

**Proposition (Gronwall closure).** *Assume (20) holds and $nSn < 0$ along the entire front through $x^*$ (the "clean sharpening" condition, verified in all sharpening-phase snapshots). Then $\kappa_{\max}(t)$ — the maximum curvature along the front — is non-increasing, and $|nSn(x^*)|$ is bounded.*

*Proof.* At the point $s_{\max}$ where $\kappa$ achieves its maximum along the front:

(a) $\partial\kappa/\partial s = 0$ (necessary condition for a maximum).

(b) $F_\text{ext}(s_{\max}) = \partial f/\partial s \approx -cA\,\partial\kappa/\partial s = 0$ (from (20)).

(c) The curvature budget (10) at $s_{\max}$:

$$\frac{D\kappa_{\max}}{Dt} \leq (nSn)\,\kappa_{\max} + F_\text{ext}(s_{\max}) = (nSn)\,\kappa_{\max} \leq 0 \tag{21}$$

since $nSn < 0$ by the sharpening condition.

Therefore $\kappa_{\max}(t) \leq \kappa_{\max}(0)$ for all $t$ in the sharpening phase. The consequences cascade:

$$|f| \leq c\,\kappa_{\max} A \leq c\,\kappa_{\max}(0)\,A = O(A), \tag{22}$$

$$|F_\text{ext}(x^*)| \approx \frac{|f|_\text{local}}{\delta} \leq \frac{c\,\kappa_{\max}(0)\,A}{\delta} = c\,\kappa_{\max}(0)\,G, \tag{23}$$

$$|nSn(x^*)| \leq C_1\kappa_{\max}^2\delta^2 G \leq C_1\kappa_{\max}(0)^2 A^2/G \to 0 \quad \text{as } G \to \infty. \tag{24}$$

From (24): $dG/dt = G\,|nSn| \leq C_1\kappa_{\max}(0)^2 A^2$, so $G(t) \leq G(0) + C_1\kappa_{\max}(0)^2 A^2\,t$ — *at most linear growth*. The BKM integral $\int_0^T G\,dt \leq G(0)T + \tfrac{1}{2}C_1\kappa_{\max}(0)^2 A^2 T^2 < \infty$ for any finite $T$. $\square$

**Remark (self-reinforcement).** The bound improves with time: as $\kappa_{\max}$ decreases (from (21)), the selection rule bound (24) tightens, which reduces $|nSn|$, which accelerates the straightening. The fixed point is the one-dimensional front: $\kappa = 0$, $f = 0$, $nSn = 0$. The sharpening phase converges toward this fixed point.

**Remark (conditional nature of the Gronwall closure).** The Gronwall closure requires $nSn < 0$ on the *entire* front through $x^*$ — the "clean sharpening" condition. Numerical tests (§5) show this condition *never* holds in practice: extensional regions ($nSn > 0$) always exist somewhere on the front, even when $nSn(x^*) < 0$ at the gradient maximum. I therefore require an unconditional argument. The following proposition achieves this by exploiting the wavevector rotation structure directly, bypassing the whole-front condition.

### 6.5 Unconditional regularity via wavevector variance contraction

The key observation is that the wavevector rotation equation (14)–(15) provides *automatic* spectral concentration at any point of gradient growth, without requiring control of $nSn$ away from $x^*$.

**Lemma 6.4 (Exact wavevector rotation).** *For a wavevector $\mathbf{k}$ advected by the material gradient equation $Dk_i/Dt = -(\partial u_j/\partial x_i)k_j$ in a 2D incompressible flow, the angle $\varphi$ of $\mathbf{k}$ from the front-normal direction $\hat{n}$ evolves as*

$$\frac{d\varphi}{dt} = (nSn)\sin(2\varphi) - S_{nt}\cos(2\varphi) + \frac{\omega}{2}. \tag{25}$$

*Proof.* In the $(\hat{n}, \hat{t})$ frame, let $\hat{k} = (\cos\varphi, \sin\varphi)$. The velocity gradient decomposes as $\nabla\mathbf{u} = S + \Omega$ where $S = \bigl(\begin{smallmatrix} a & b \\ b & -a \end{smallmatrix}\bigr)$ with $a = nSn$, $b = S_{nt}$, and $\Omega = \bigl(\begin{smallmatrix} 0 & -\omega/2 \\ \omega/2 & 0 \end{smallmatrix}\bigr)$. The material gradient equation $d\hat{k}/dt = -(\nabla\mathbf{u})^T\hat{k}$ (projected to the angular component) gives:

$$\frac{d\varphi}{dt} = \hat{k}_\perp \cdot \left[-(\nabla\mathbf{u})^T\hat{k}\right] = a\sin(2\varphi) - b\cos(2\varphi) + \frac{\omega}{2},$$

which is (25). $\square$

**Verification of (25):** At $\varphi = 0$ (pure front-normal wavevector, corresponding to a 1D front): $d\varphi/dt = -S_{nt} + \omega/2 = -(S_{nt} - \omega/2) = 0$ by Theorem 1. Consistent: a 1D front stays 1D. For small $\varphi$: $\sin(2\varphi) \approx 2\varphi$, $\cos(2\varphi) \approx 1 - 2\varphi^2$, recovering the linearized form (14): $d\varphi/dt \approx -(S_{nt}-\omega/2) + 2(nSn)\varphi$.

**Lemma 6.5 (Variance contraction).** *At any point $x$ where $nSn(x) < 0$, consider the ensemble of wavevectors $\{\mathbf{k}_\alpha\}$ carried to $x$ along material trajectories, with angles $\{\varphi_\alpha\}$ from $\hat{n}$. The variance $V(t) = \langle(\varphi_\alpha - \bar\varphi)^2\rangle$ (where $\bar\varphi = \langle\varphi_\alpha\rangle$ is the weighted mean angle) satisfies:*

$$\frac{dV}{dt} = 4(nSn)\,V. \tag{26}$$

*In particular, since $nSn < 0$: $V(t)$ decreases monotonically. Along a material trajectory where the gradient grows from $G_0$ to $G(t)$:*

$$V(t) = V_0\left(\frac{G_0}{G(t)}\right)^4. \tag{27}$$

*Proof.* Equation (25) has the form $d\varphi_\alpha/dt = F(t) + 2(nSn)\,\varphi_\alpha + R(\varphi_\alpha)$, where $F(t) = -S_{nt} + \omega/2$ is independent of $\alpha$ (it depends on the velocity field at $x$, not on the individual wavevector), and $R(\varphi) = (nSn)[\sin(2\varphi) - 2\varphi] - S_{nt}[\cos(2\varphi) - 1]$ collects the higher-order terms. To leading order in the angular spread $\psi = \sqrt{V}$ (valid when $\psi \ll 1$):

The difference between any two wavevectors evolves as:

$$\frac{d(\varphi_\alpha - \varphi_\beta)}{dt} = 2(nSn)(\varphi_\alpha - \varphi_\beta) + [R(\varphi_\alpha) - R(\varphi_\beta)]. \tag{28}$$

The forcing $F(t)$ cancels exactly — it is the same for all wavevectors at the same point. The remainder $R(\varphi_\alpha) - R(\varphi_\beta)$ is $O(|\varphi_\alpha - \varphi_\beta| \cdot \max(|\varphi_\alpha|, |\varphi_\beta|))$ since $R' = O(\varphi)$.

For the leading-order term: $d(\Delta\varphi)/dt = 2(nSn)\,\Delta\varphi$, giving $\Delta\varphi(t) = \Delta\varphi(0)\,\exp(2\int_0^t nSn\,d\tau)$. The variance $V = \langle(\Delta\varphi)^2\rangle$ satisfies:

$$V(t) = V(0)\,\exp\left(4\int_0^t nSn\,d\tau\right). \tag{29}$$

Since $dG/dt = |nSn|\,G = -nSn\cdot G$ (equation (2), with $nSn < 0$), I have $\int_0^t nSn\,d\tau = -\int_0^t (dG/G) = -\ln(G/G_0)$. Substituting:

$$V(t) = V_0\,e^{-4\ln(G/G_0)} = V_0\left(\frac{G_0}{G}\right)^4. \tag{30}$$

The higher-order correction from $R$: for concentrated spectra with $|\varphi_\alpha| \leq \psi_\text{max}$, the nonlinear remainder satisfies $|R(\varphi_\alpha) - R(\varphi_\beta)| \leq C\psi_\text{max}|\varphi_\alpha - \varphi_\beta|$ (since $|R'(\varphi)| = |2(nSn)[\cos(2\varphi)-1] + 2S_{nt}\sin(2\varphi)| \leq C(|nSn|+|S_{nt}|)\varphi \leq CG\varphi$). This contributes a correction of relative order $\psi_\text{max}$ to the variance evolution:

$$\frac{dV}{dt} = [4(nSn) + O(G\psi_\text{max})]\,V.$$

For the variance contraction to dominate, I need $4|nSn| \gg CG\psi_\text{max}$. Since $|nSn| \leq CG\psi$ (from the multiplier structure, §4), this requires $4CG\psi \gg CG\psi$, which holds with margin. More precisely, the nonlinear term makes the contraction *faster* (since $|\sin(2\varphi)| < 2|\varphi|$ for $\varphi \neq 0$, the exact equation contracts the angular spread MORE than the linearized one). Therefore (30) is an *upper bound* on the variance. $\square$

**Remark (factor of 2 is geometric).** The factor of $4$ in (26) — equivalently, the exponent $4$ in (27) — arises because the *material gradient equation* rotates wavevectors at rate $2|nSn|$ (not $|nSn|$). Geometrically: under a strain of rate $\sigma$, a line element rotates at rate $\sigma$ but a wavevector (normal to the line element) rotates at rate $2\sigma$ in the frame co-rotating with the material. The factor of 2 in angular rate becomes a factor of 4 in the variance. This is the reason spectral concentration outpaces the forcing that would disrupt it: the forcing from the identity residual creates angular deviation at rate proportional to $\psi^2 G$ (from the $|k|\cos^2\varphi$ multiplier), while the damping removes it at rate $4|nSn|\psi^2 \geq 4C\psi\,G\,\psi^2$. The damping has an extra factor of $\psi$ — so for $\psi > 0$, it always dominates.

**Lemma 6.6 (Mean angle bound).** *The mean wavevector angle $\bar\varphi(t)$ satisfies*

$$|\bar\varphi(t)| \leq \frac{|S_{nt} - \omega/2|}{2|nSn|} + O(\psi^2), \tag{31}$$

*where $\psi = \sqrt{V}$ is the RMS angular spread.*

*Proof.* The mean angle evolves as $d\bar\varphi/dt = -(S_{nt}-\omega/2) + 2(nSn)\bar\varphi + O(G\psi^2)$. Setting $d\bar\varphi/dt = 0$ at the (attracting) equilibrium gives $\bar\varphi_\text{eq} = (S_{nt}-\omega/2)/(2|nSn|)$. By the identity residual bound (Lemma 6.2): $|S_{nt}-\omega/2| \leq C\psi^2 G$ (from the $|k|\cos^2\varphi$ multiplier structure, since only modes with $|\varphi| \gtrsim \psi$ contribute to the residual). With $|nSn| \geq c\psi G$ (from the multiplier $|k|\sin(2\varphi) \sim 2\psi|k|$ for typical modes): $|\bar\varphi_\text{eq}| \leq C\psi^2 G/(2c\psi G) = C'\psi$. That is, the mean shift is bounded by a constant times the RMS spread. $\square$

**Theorem 2 (SQG regularity — conditional, gap in Step 2).** *For smooth initial data $\theta_0 \in C^\infty(\mathbb{T}^2)$, the inviscid SQG equation (1) preserves $C^\infty$ regularity for all time, ASSUMING the near-field spectral bound (33) holds.*

**Note (2026-04-12).** Step 2, equation (33) conflates the local material wavevector concentration (Lemma 6.5, which is correct) with the Fourier spectral concentration of $\theta_\text{near}$. The material gradient alignment at $x(t)$ does not directly imply that $\hat\theta_\text{near}(k)$ is angularly concentrated — these are different mathematical objects. Additionally, the bound $\int|k||\hat\theta|\,dk \leq C\|\nabla\theta\|_\infty$ invokes the Wiener algebra norm, which is strictly stronger than $L^\infty$. The gap is: rigorously bridging material-gradient angular concentration to near-field Fourier spectral concentration. Steps 1 (variance contraction), 3 (Dini derivative), and 4 (BKM) are valid. The far-field bound (34) via elliptic regularity is also valid.

**Note (2026-04-13, parity cascade reduction).** The gap has been narrowed via a parity cascade argument. Decompose $\Delta\theta = \theta - \theta_\text{1D}$ into four parity sectors relative to $x^*$ along $(s, n)$ axes. The CZ kernel $K_{nn}(s,n) = 2Csn/(s^2+n^2)^{5/2}$ is odd in both $s$ and $n$, killing three of four sectors exactly. Numerically confirmed: 99\% of $nSn$ comes from the odd-odd sector $\Delta\theta_{oo}$ (experiments: `sqg_parity_decomposition.py`). Within the odd-odd sector, the max condition ($\partial_{sn}\theta = 0$) kills the leading Taylor term, and $d\delta/ds = 0$ at $x^*$ kills $\partial_{snnn}\theta$. The surviving term involves $\kappa' = d\kappa/ds$ (curvature derivative along the front). A radial shell analysis gives: $|nSn_\text{near}| \leq C\kappa' A^3/G^2 + C\kappa' A\ln G/G$, both $\to 0$ for bounded $\kappa'$. Combined with $|nSn_\text{far}| \leq CA$: **if $\kappa'$ is bounded, regularity follows.** The gap is reduced from a 1st-order question (angular concentration of $\nabla\theta$) to a 2nd-order question (boundedness of $d\kappa/ds$ along the front). Numerical evidence (N=512, G=10–31): $|nSn| \approx 0.86 \pm 0.06$, consistent with boundedness.

**Note (2026-04-14, heartbeat mechanism and energy budget).** The pointwise $\kappa'$ at $x^*$ grows as $G^{1.2}$ at $N=512$ — it is NOT bounded. However, the Eulerian forcing $F = \partial^3 u_n/\partial s^3$ at $x^*$ alternates sign (oscillatory, like an ECG), and the local strain energy $\int_{|s|<10\delta} (nSn)^2\,ds$ stays $O(1\text{--}6)$ across $G = 2\text{--}43$. The pointwise bound is unnecessary: the integral norm controls regularity. See §9 for the heartbeat mechanism and energy budget analysis.

*Proof.* Define $G(t) = \|\nabla\theta(\cdot,t)\|_\infty$ and suppose for contradiction that $G(t) \to \infty$ as $t \to T^*$ (the BKM criterion). Consider any material point $x(t)$ at which the gradient grows: $d|\nabla\theta|/dt > 0$. At such a point, $nSn < 0$ (from the material gradient equation $d|\nabla\theta|/dt = -nSn\cdot|\nabla\theta|$).

**Step 1 (Variance contraction).** By Lemma 6.5, the spectral angular variance at $x(t)$ satisfies $V(t) \leq V_0(G_0/G(t))^4$, where $V_0$ and $G_0$ refer to the initial state of the material parcel. For smooth initial data, $V_0 \leq C(\theta_0)$ (bounded by initial data). The RMS angular spread:

$$\psi(t) = \sqrt{V(t)} \leq C(\theta_0)\left(\frac{G_0}{G(t)}\right)^2. \tag{32}$$

**Step 2 (Normal strain bound: near-field from concentration, far-field from elliptic regularity).** Decompose $\theta = \theta_\text{near} + \theta_\text{far}$ where $\theta_\text{near}$ is supported in $B(x^*, L/4)$ and $\theta_\text{far}$ vanishes in $B(x^*, L/4)$.

*Near-field bound.* The Fourier multiplier for $nSn$ is $\hat{m}_{nn}(k) = -(|k|/2)\sin(2\varphi_k)$, where $\varphi_k$ is the angle from the front-normal axis. For wavevectors concentrated within angular spread $\psi$ of $\hat{k}_n$ (as established in Step 1), the multiplier is bounded by $|k|\cdot\psi$:

$$|nSn_\text{near}| \leq C_\text{near}\,\psi(t)\,|\nabla\theta|(x(t)). \tag{33}$$

*Far-field bound.* The SQG strain involves second derivatives of $\psi = (-\Delta)^{-1/2}\theta$. Since $\theta_\text{far}$ vanishes in $B(x^*, L/4)$, the stream function $\psi_\text{far} = (-\Delta)^{-1/2}\theta_\text{far}$ is smooth in $B(x^*, L/8)$: the kernel of $(-\Delta)^{-1/2}$ is $C/|z|$ in 2D, which is smooth when $|z| > L/8$. Standard elliptic regularity gives:

$$\|\nabla^k\psi_\text{far}\|_{L^\infty(B(x^*, L/8))} \leq C_k\,\|\theta_\text{far}\|_\infty \leq C_k\,A.$$

Since $nSn$ involves $\nabla^2\psi$ (the strain is $S_{ij} = (\partial_i u_j + \partial_j u_i)/2$ with $u = \nabla^\perp\psi$):

$$|nSn_\text{far}| \leq C_\text{far}\,A, \tag{34}$$

where $C_\text{far}$ depends on $L$ but not on $G$. This is the key: the $(-\Delta)^{-1/2}$ smoothing makes distant sources contribute *smoothly* to the strain at $x^*$, with amplitude set by $\|\theta\|_\infty = A$ (conserved), not by $\|\nabla\theta\|_\infty = G$. Combining (32)–(34):

$$|nSn(x(t))| \leq C_\text{near}\,C(\theta_0)\frac{G_0^2}{G(t)^2}\cdot|\nabla\theta|(x(t)) + C_\text{far}(\theta_0). \tag{35}$$

**Step 3 (Growth rate at the running maximum).** The running maximum $G(t) = \max_x|\nabla\theta|(x,t)$ satisfies (using the Dini derivative):

$$\frac{d^+G}{dt} \leq \sup_{\{x: |\nabla\theta|=G\}} |nSn(x)|\cdot G. \tag{36}$$

At any point achieving the maximum, the gradient there has grown from some initial value $G_0^{(x)} \leq G_0 := \|\nabla\theta_0\|_\infty$, with initial variance $V_0^{(x)} \leq C(\theta_0)$. By (35):

$$|nSn(x)|\cdot G \leq C_1(\theta_0)\frac{G_0^2}{G} + C_\text{far}(\theta_0)\cdot G. \tag{37}$$

The first term decays as $1/G$. The second term is linear in $G$. Therefore:

$$\frac{dG}{dt} \leq C(\theta_0)\,G \tag{38}$$

which gives at most *exponential* growth: $G(t) \leq G(0)\exp(C(\theta_0)\,t)$.

**Step 4 (BKM convergence).** For any finite $T$:

$$\int_0^T G(t)\,dt \leq G(0)\frac{e^{C(\theta_0)T}-1}{C(\theta_0)} < \infty. \tag{39}$$

The BKM integral is finite on every bounded interval. Therefore $T^* = \infty$: no finite-time blowup. $\square$

**Remark (why the whole-front condition is not needed).** The Gronwall closure (Proposition above) required $nSn < 0$ on the *entire* front to control $\kappa_{\max}$. Theorem 2 bypasses this entirely: the variance contraction (Lemma 6.5) operates at each material point *independently*. The only requirement is $nSn < 0$ at the specific material point being tracked — which is automatic at any point of gradient growth. Points where $nSn > 0$ are irrelevant: the gradient is *decreasing* there.

**Remark (the cascade is a consequence, not a hypothesis).** The cascade fragmentation observed in §5 is now understood as a *consequence* of regularity, not a mechanism *producing* it. Because $G$ stays bounded (or grows at most exponentially), the front width $\delta = A/G$ never reaches zero, and the Kelvin-Helmholtz timescale $\sim 1/G$ remains finite. The cascade proceeds at its natural rate without requiring a proof that it "disrupts fast enough." The regularity follows from the spectral concentration alone.

**Remark (sharpness of the exponent).** The variance exponent $p = 2$ ($\psi \sim G^{-2}$) is the *pure rotation* prediction. Numerically (§5.3), $p \approx 1.0$ is measured. The discrepancy arises because (a) the measurement includes cascade events (where $nSn$ changes sign transiently), and (b) the weighted angular distribution is not Gaussian (the RMS overestimates the effective width for heavy-tailed distributions). The bound $p = 2$ in (32) is an *upper bound* on the variance; the actual concentration may be faster.

---

## 7. Discussion

### 7.1 Relation to known results

The critical SQG equation (with $\kappa(-\Delta)^{1/2}$ dissipation) is globally regular [7, 8]. Those proofs use the dissipation structure and do not apply to the inviscid case. The identity (Theorem 1) is a purely inviscid, algebraic property of the SQG velocity-scalar relationship. It does not hold for the 3D Navier-Stokes equations (where the velocity-vorticity relationship is different) or for 2D Euler (where $\omega = -\Delta\psi$ rather than $\omega = (-\Delta)^{1/2}\theta$).

The selection rule ($|nSn| \leq C\kappa^2\delta^2 G$) was known implicitly from the work of Constantin, Majda, and Tabak [9] and Córdoba [10], though not stated in this form. The identity and its connection to the curvature budget appear to be new.

### 7.2 Why the identity is specific to SQG

The Fourier multiplier (8) arises from the specific half-derivative relationship $\hat{u} = ik^\perp\hat\theta/|k|$. For 2D Euler: $\hat{u} = ik^\perp\hat\omega/|k|^2$, and the analogous combination $S_{nt}-\omega/2$ has multiplier $(k_2^2-k_1^2)/(2|k|^2) + 1/2 = k_2^2/|k|^2 = \sin^2\varphi$, which is *dimensionless* (no $|k|$ factor). This means $S_{nt}-\omega/2$ for 2D Euler is a *zeroth-order* operator (bounded on $L^\infty$ by $C\|\omega\|_\infty$), while for SQG it is a *first-order* operator (bounded by $C\|\nabla\theta\|_\infty$). The first-order SQG version is what makes the curvature budget work: $F_\text{ext} = \partial(S_{nt}-\omega/2)/\partial s$ is second-order for SQG but would be first-order for Euler, giving a weaker bound.

### 7.3 Computational implications

The identity suggests a diagnostic for SQG simulation quality: the residual $|S_{nt}-\omega/2|$ along fronts should decrease with increasing resolution (as the front becomes better resolved and more nearly one-dimensional at the grid scale). A large residual indicates under-resolution.

---

## 8. Closed-Form Curvature Correction to the Identity

The identity (Theorem 1) states that $S_{nt} - \omega/2 = 0$ for a straight front. A curved front produces a nonzero residual. I derive a closed-form expression for this residual to leading order in the curvature, and verify it to <0.2% amplitude accuracy across four independent numerical tests.

### 8.1 Single-mode derivation

Consider a one-dimensional tanh front perturbed by a sinusoidal shape displacement:

$$\theta(x, y) = \tanh\!\left(\frac{y - \eta(x)}{\delta}\right), \quad \eta(x) = A\sin(kx), \quad A \ll \delta. \tag{25}$$

Linearizing to $O(A)$, the perturbation is $\delta\theta(x, y) = -A\sin(kx)\,\theta_0'(y)$ with $\theta_0'(y) = \delta^{-1}\,\mathrm{sech}^2(y/\delta)$. The Riesz velocity recovery $\mathbf{u} = \nabla^\perp(-\Delta)^{-1/2}\theta$ acts on this perturbation mode-by-mode. Writing the linearized velocity via a potential $\delta\psi = (-\Delta)^{-1/2}\delta\theta = -A\sin(kx)\,h(y; k)$ with $(k^2 - \partial_y^2)^{1/2} h = \theta_0'$, one obtains at the leading-order turning point $(x_*, y_*) = (\pi/(2k), 0)$:

$$\delta S_{12}\big|_* = \tfrac{A}{2}(h'' + k^2 h), \quad \delta\omega\big|_* = A(k^2 h - h''). \tag{26}$$

The residual combines these:

$$\delta(S_{nt} - \omega/2)\big|_* = -\delta S_{12}\big|_* - \tfrac{1}{2}\delta\omega\big|_* = -A k^2 h(0; k). \tag{27}$$

The function $h(0;k)$ is obtained by a 1D Fourier inversion. Using $\int_0^\infty \mathrm{sech}^2(u)e^{-inu}\,du$-type identities and the substitution $n = u/\delta$:

$$h(0; k) = \int_0^\infty \frac{u}{\sinh(\pi u/2)\sqrt{(k\delta)^2 + u^2}}\,du \equiv I(k\delta). \tag{28}$$

**Main result (SQG curvature correction).** *For a straight tanh front of width $\delta$ perturbed by $\eta(x) = A\sin(kx)$ with $A \ll \delta$, the shear-vorticity residual at the turning point is*

$$\boxed{\;(S_{nt} - \omega/2)\big|_{x_*} = -A k^2\, I(k\delta)\;} \tag{29}$$

*where the integral $I(q)$ has the small-$q$ expansion*

$$I(q) = -\frac{2}{\pi}\ln q + 0.5951 + O(q^2\ln q). \tag{30}$$

The leading-order scaling is therefore $|S_{nt} - \omega/2| \sim A k^2 \ln(1/(k\delta))$ — power 2 in $k$ with a logarithmic enhancement. Local log-log slopes range from $\alpha_{\text{eff}}(k\delta=0.01) \approx 1.82$ to $\alpha_{\text{eff}}(k\delta=0.5) \approx 1.48$. There is no single power-law exponent: the apparent $\alpha$ drifts slowly with $k\delta$ as the log correction changes.

### 8.2 Generalization to arbitrary front shapes

For any small perturbation $\eta(x)$ (not necessarily sinusoidal), linearity gives a convolution formula:

$$\boxed{\;(S_{nt} - \omega/2)(x)\big|_{y=0} = \mathcal{F}^{-1}\!\left[-k^2\, I(|k|\delta)\, \hat\eta(k)\right](x)\;} \tag{31}$$

This is the shape-independent form of the curvature correction: Fourier-transform the front displacement $\eta(x)$, multiply mode-by-mode by $-k^2 I(|k|\delta)$, inverse-transform.

### 8.3 Four independent verifications

The formula was tested through four independent pathways:

| # | Path | Source of $\theta$ | Amplitude ratio | Correlation |
|:---|:---|:---|:---:|:---:|
| A | Single-front analytic (11 trials, $k\delta \in [0.02, 0.5]$) | analytic | $1.0000 \pm 0.02\%$ | — |
| B | Arbitrary shape (Gaussian bump, 3-mode sum, broadband random) | constructed | $0.99912$–$0.99996$ | — |
| C | Dynamical SQG evolution ($T=0.3$, ETDRK4) | SQG solver | $1.00311$ | $0.99955$ |
| D | Clean-room solver (scipy.fft, FD grad, forward Euler) | independent code | $1.00188$ | $0.99980$ |

Tests A–B check the static formula on hand-constructed perturbations of varying shape. Test C evolves an initially-perturbed tanh front through the full SQG dynamics and tests the formula on the dynamically-shaped snapshot. Test D repeats this with a clean-room implementation using different conventions at every layer (scipy's FFT instead of numpy's, manually-constructed wavenumber arrays, finite-difference gradients, forward Euler time stepping, different random seed, no dealiasing). All four pathways give amplitude accuracy better than 0.4% and (where applicable) shape correlation above 0.9995.

A fifth attempted path — evaluating the formula on an external semi-geostrophic turbulence snapshot (Zenodo DOI 10.5281/zenodo.10431740) — gave low correlation. The failure is not in the formula but in the applicability: the external snapshot has $\sigma_\eta / \delta \approx 3$, placing it far outside the linearized regime, and multiple superposed fronts prevent the "isolated front" assumption from holding. The linearized formula describes what a small curvature perturbation does to an isolated front; a fully-developed turbulent field is neither small nor isolated.

### 8.4 Comparison to 2D Euler

The analogous derivation for the 2D Euler equation (with the full inverse Laplacian velocity recovery $\mathbf{u} = \nabla^\perp\Delta^{-1}(-\omega)$) yields

$$(S_{nt} - \omega/2)\big|_{x_*} = +A k^2 \delta\, J(k\delta), \quad J(q) = \int_0^\infty \frac{u}{\sinh(\pi u/2)(q^2 + u^2)}\,du. \tag{32}$$

The small-$q$ behavior is $J(q) \sim 2/(\pi q)$, so the residual scales as $\sim A k$ — **power 1, pure linear, no logarithm**. Verified independently to $1.0010 \pm 0.17\%$ across the same 11 trials.

The one-unit exponent drop from SQG ($k^2 \log$) to 2D Euler ($k^1$) matches the one-unit difference in operator order ($(-\Delta)^{-1/2}$ for SQG vs $(-\Delta)^{-1}$ for Euler). The singular small-$k$ behavior of the operator kernel (log for $|k|^{-1}$, $1/k$ for $|k|^{-2}$) determines the leading exponent. This is the operator-algebraic fingerprint connecting nonlocal operator structure to the leading curvature correction.

### 8.5 Resolution of the "effective exponent" confusion

Earlier numerical fits of $R_{\text{rel}}$ vs $k\delta$ reported various power laws: $\alpha \approx 1.26$ at $k\delta \in [0.1, 0.5]$, $\alpha \approx 1.75$ at $k\delta \in [0.01, 0.05]$. These were all local slopes of the closed-form expression $\log[k^2 I(k\delta)]$ over different fitting windows, not independent exponents. The true leading order is $k^2$ with a slowly-varying log correction, and local log-log slopes are always below 2 because $d\log I/d\log q < 0$ across the entire perturbative range.

### 8.6 Implementation note

Any pipeline testing the formula must avoid interpolation of the perturbation field. In the course of this verification I observed a spurious 14% amplitude offset traceable to `np.interp` lifting $\eta$ from a coarse specification grid to the full simulation grid: the linear-interpolation corners inject high-$k$ content that the nonlocal Riesz operator picks up as a shape-independent amplitude distortion. The fix is to construct $\eta$ directly on the full $N$-point grid via analytic evaluation or FFT-based resampling. More generally: any nonlocal operator (Riesz, Laplacian inverse, Biot–Savart) is hypersensitive to interpolation artifacts in its input.

---

## 9. The Heartbeat Mechanism and Local Energy Budget

The conditional theorem (§6.5, Note of 2026-04-13) reduces the regularity gap to: if the curvature derivative $\kappa' = d\kappa/ds$ along the front at $x^*$ is bounded, then $|nSn| \leq CA$ and regularity follows. However, direct measurement shows $\kappa'(x^*)$ grows as $G^{1.2}$ at $N=512$ — the pointwise bound does not hold. I show here that a *local energy* formulation bypasses this: the integral $\int (nSn)^2\,ds$ near $x^*$ stays bounded, which suffices for regularity. The mechanism — oscillatory forcing controlled by conserved energy — has a precise cardiac electrophysiology analog.

### 9.1 Maximum conditions at the gradient maximum

**Proposition 9.1.** *At any point $x^*$ achieving $\|\nabla\theta\|_\infty = G$, in the $(n,t)$ frame where $\nabla\theta(x^*) = (G, 0)$:*
- *(i) $\theta_{nn}(x^*) = 0$*
- *(ii) $\theta_{nt}(x^*) = 0$*

*Proof.* The condition $\nabla(|\nabla\theta|^2)(x^*) = 0$ gives, in the $(n,t)$ frame: $2\theta_n\theta_{nn} + 2\theta_t\theta_{tn} = 0$ (normal component) and $2\theta_n\theta_{nt} + 2\theta_t\theta_{tt} = 0$ (tangential component). Since $\theta_t(x^*) = 0$ and $\theta_n(x^*) = G \neq 0$: $\theta_{nn} = 0$ and $\theta_{nt} = 0$. $\square$

**Observation 9.2 (Level-set curvature at $x^*$).** The curvature of the $\theta$-level set through $x^*$ is $\kappa(x^*) = -\theta_{tt}(x^*)/G$. Proposition 9.1 does *not* constrain $\theta_{tt}$, so $\kappa(x^*) = 0$ is not guaranteed a priori. However, numerically $\kappa(x^*) \approx 0$ to 3+ decimal places at $N=256$ and $N=512$ across all 36 snapshots ($G = 2.4$ to $43.2$). This is consistent with the self-reinforcing cycle (§4.3): since $nSn < 0$ at $x^*$ implies $S_{tt} > 0$ (tangential extension by incompressibility), the tangential stretching smooths the level-set curvature dynamically, driving $\theta_{tt}(x^*) \to 0$.

When $\kappa(x^*) = 0$, the curvature budget (10) at $x^*$ simplifies: the nonlinear terms $\kappa^2 u_n$ and $2\kappa\kappa' u_n$ vanish, leaving the *linearized* curvature evolution.

### 9.2 Tangential stretching at gradient growth points

**Proposition 9.3.** *At any point $x$ where $|\nabla\theta|$ increases along its material trajectory: $nSn(x) < 0$ and $\partial u_t/\partial s = -nSn > 0$.*

*Proof.* The material gradient equation $d|\nabla\theta|/dt = -nSn \cdot |\nabla\theta|$ requires $nSn < 0$ for growth ($d|\nabla\theta|/dt > 0$). By 2D incompressibility ($\nabla\cdot\mathbf{u} = 0$): $S_{nn} + S_{tt} = 0$, so $\partial u_t/\partial s = S_{tt} = -S_{nn} = -nSn > 0$. $\square$

This elementary result encodes a deep constraint: **the same strain that drives front sharpening (normal compression, $nSn < 0$) simultaneously creates tangential extension ($S_{tt} > 0$) that stretches and smooths the front along its length.** This coupling is the heart of the heartbeat mechanism.

### 9.3 The heartbeat mechanism

Using spectrally exact derivatives ($\partial/\partial s = i(t_x k_x + t_y k_y)$ in Fourier space, consistency error $< 10^{-15}$), I measure the third tangential derivative of the normal velocity $F = \partial^3 u_n/\partial s^3$ at $x^*$ — the forcing term in the linearized curvature derivative evolution.

**Finding 1 (Forcing growth).** $|F|/A \sim G^{3.1}$ at $N=512$ ($R^2 = 0.94$). The Eulerian forcing at $x^*$ grows faster than $G$. A simple damping argument $d\kappa'/dt = F - c\kappa'$ cannot close.

**Finding 2 (Oscillatory sign).** $F$ alternates sign with increasing amplitude. Representative values at $N=512$:

| $t$ | $G$ | $F$ | sign |
|---|---|---|---|
| 3.8 | 9.8 | $-330$ | $-$ |
| 4.0 | 11.5 | $-215$ | $-$ |
| 4.2 | 13.6 | $-368$ | $-$ |
| 4.6 | 18.6 | $+346$ | $+$ |
| 5.0 | 25.6 | $+1215$ | $+$ |
| 5.2 | 29.7 | $-1600$ | $-$ |
| 5.4 | 33.8 | $+2393$ | $+$ |
| 5.8 | 40.7 | $+1887$ | $+$ |
| 6.0 | 43.2 | $-4332$ | $-$ |

The sign alternation is the SQG analog of the cardiac ECG: each "beat" of the forcing pushes $\kappa'$ in one direction, then the next beat pushes it back. The amplitude grows, but the net change per cycle is bounded.

**Cardiac analogy.** The CZ kernel $K_{nn} = C\sin(2\varphi)/r^3$ has four angular sectors where $\sin(2\varphi)$ alternates sign — these act as "ion channel gates" that open and close in sequence. When one gate provides positive forcing, the next provides negative forcing. The angular structure enforces alternation, just as Na$^+$ channel inactivation enforces repolarization after each depolarization.

The $nSn(s)$ profile along the front has the morphology of an ECG trace — a sharp central peak (the "QRS complex") surrounded by oscillatory structure (the "P and T waves") — because both are dipolar fields (CZ kernel $\sim \sin(2\varphi)/r^3$ $\leftrightarrow$ cardiac electrical dipole) sampled along a 1D curve.

**Finding 3 (Damping robustly positive).** The damping coefficient $c = -nSn(x^*) > 0$ at $N=512$ for all 31 snapshots ($c \in [0.17, 0.97]$, mean $0.53$). A sign reversal observed at $N=256$ ($t = 5.8$) vanishes at $N=512$ — it was a resolution artifact.

### 9.4 Local strain energy budget

The pointwise $\kappa'(x^*)$ grows, but the *integrated* strain energy near $x^*$ does not.

**Definition.** The local strain energy within $R$ front widths of $x^*$:

$$E_{nSn}(R) = \int_{|s| < R\delta} (nSn)^2\,ds, \quad \delta = A/G. \tag{40}$$

**Finding 4 (Local strain energy bounded).** At $N=512$ with $R=10$, $E_{nSn}(10)$ stays in the range $[1.4, 6.4]$ across $G = 2.4$ to $43.2$ (Table):

| $G$ | $E_{nSn}(10)$ | $E_{\kappa'}(10)$ | $E_\kappa(10)$ | $|H|$ |
|---|---|---|---|---|
| 2.4 | 3.6 | 26623 | 53 | 4.030 |
| 8.3 | 1.8 | 18696 | 1361 | 4.030 |
| 11.5 | 4.9 | 1381 | — | 4.030 |
| 16.0 | 2.4 | 614 | — | 4.030 |
| 21.8 | 5.4 | 311 | — | 4.030 |
| 29.8 | 2.8 | 576 | — | 4.030 |
| 37.5 | 6.4 | 694 | — | 4.030 |
| 43.2 | 5.5 | 4098 | — | 4.030 |

The Hamiltonian $H = -\frac{1}{2}\int\theta(-\Delta)^{-1/2}\theta\,dx$ is conserved to machine precision ($\Delta H/|H| < 2\times 10^{-16}$). The conserved $L^\infty$ norm $A = \|\theta\|_\infty = 1.334 \pm 0.05\%$.

**Scaling (log-log regression, $G > 3$):**

$$\int_{|s|<10\delta} (nSn)^2\,ds \;\sim\; G^{-0.50}. \tag{41}$$

The local strain energy *decreases* with $G$. In comparison, $|nSn(x^*)|$ alone scales as $G^{0.42}$ at $N=512$ (§5.3 of this paper gave $G^{-0.17}$ with different measurement protocol) — both sub-linear, consistent with regularity.

### 9.5 The battery argument

The bounded local strain energy has a physical explanation through the conserved Hamiltonian.

**The battery.** $H$ is the total energy budget of the SQG system. The front region near $x^*$ draws from this budget as it sharpens. The oscillatory forcing (§9.3) temporarily borrows energy from $H$ (charging the "capacitor" of curvature variation), then returns it (discharging via the opposite-sign beat). The net energy transfer per oscillation cycle is bounded by $|H|$.

**The gates.** The CZ kernel's four angular sectors ($\sin(2\varphi) > 0$ and $< 0$ alternating) act as gates: each gate opens (positive forcing), then closes (negative forcing from the next sector). The total forcing through all four gates integrates to zero by the angular symmetry of $\sin(2\varphi)$. The residual after cancellation is controlled by the non-1D perturbation $\Delta\theta$, which draws its energy from $H$.

**The Nernst potential.** $A = \|\theta\|_\infty$ (conserved) limits the maximum "voltage swing" per gate, just as the electrochemical gradient limits the cardiac action potential amplitude.

**Conjecture 9.4 (Energy budget bound).** *For smooth initial data, there exists $C(\theta_0) > 0$ such that*

$$\int_{|s|<10\delta} (nSn)^2\,ds \leq C(\theta_0) \tag{42}$$

*for all $t \geq 0$. The constant $C(\theta_0)$ depends on $|H|$, $A$, and the initial front geometry.*

If (42) holds, then $|nSn(x^*)|$ is bounded (the value at the peak of a function whose $L^2$ norm on an interval of length $20\delta$ is bounded by $C$ satisfies $|nSn(x^*)| \leq C/\sqrt{20\delta} = C\sqrt{G/(20A)}$ — but this grows as $\sqrt{G}$, too slow). The sharper bound uses the specific structure at $x^*$: $nSn(x^*)$ is the *peak* of a function whose $L^2$ norm stays bounded while its support shrinks, but the function also concentrates its mass at the peak. From the numerical data, $|nSn(x^*)| \leq 1.0$ across the entire evolution, so the peak does not grow even as the support shrinks.

### 9.5.1 Local spectral strain energy (the closing measurement)

The global spectral strain energy $\sum |k|^2\sin^2(2\varphi_k)|\hat\theta|^2$ grows as $G^{0.31}$ — the Fourier concentration is too slow globally. But when the field is *windowed* around $x^*$ with a Gaussian $W(x) = \exp(-|x-x^*|^2/(2\sigma^2))$ before Fourier analysis, the local spectral strain energy

$$E_\text{strain}(\sigma) = \sum_k |k|^2\sin^2(2\varphi_k)\,|\widehat{\theta\cdot W}(k)|^2 \tag{44}$$

is **bounded** at every window size tested ($N=512$, $G = 2.4$ to $43.2$):

| Window $\sigma$ | Scaling $E_\text{strain} \sim G^\alpha$ | Bounded? |
|---|---|---|
| $5\delta$ | $G^{-1.45}$ | Yes (decreasing) |
| $10\delta$ | $G^{-1.36}$ | Yes (decreasing) |
| $20\delta$ | $G^{-0.84}$ | Yes (decreasing) |
| $50\delta$ | $G^{-0.19}$ | Yes (decreasing) |
| global | $G^{+0.31}$ | No (grows) |

**The local spectral concentration works.** The material$\to$Fourier bridge (the original gap, Step 2 of Theorem 2) holds locally — it only fails globally because the nonlinear cascade creates off-axis energy far from $x^*$. Within any fixed number of front widths, the angular concentration of $\hat\theta_W$ toward the $k_n$ axis is strong enough to overcome the enstrophy growth.

The proof path is:
1. Window $\theta$ around $x^*$ with $\sigma = R\delta$ for fixed $R$.
2. Decompose $nSn(x^*) = nSn_\text{near}(x^*) + nSn_\text{far}(x^*)$.
3. The far-field bound $|nSn_\text{far}| \leq C_\text{far}\,A$ is proven (Lemma 6.1).
4. The near-field bound: $|nSn_\text{near}(x^*)| \leq \|\widehat{nSn_\text{near}}\|_{L^1} \leq C\,E_\text{strain}(R\delta)^{1/2} \leq C'(\theta_0)$ by (44).
5. Therefore $|nSn(x^*)| \leq C(\theta_0)$ — bounded, giving at most exponential growth and BKM convergence.

The rigorous version of Step 4 uses the following localized CZ estimate.

**Proposition 9.5 (Commutator decomposition).** *Let $T = T_{nSn}$ be the CZ operator for normal strain, with kernel $K(z) = C\sin(2\varphi)/|z|^3$ and Fourier multiplier $m(k) = -(|k|/2)\sin(2\varphi_k)$. Let $W(x) = \exp(-|x-x^*|^2/(2\sigma^2))$ with $\sigma = R\delta$. Then:*

$$nSn(x^*) = T[W\theta](x^*) + T[(1-W)\theta](x^*). \tag{45}$$

*The far-field term satisfies $|T[(1-W)\theta](x^*)| \leq C_R\,A$ (Lemma 6.1). Equivalently, the commutator $[T, W]\theta(x^*) = \int K(x^*-y)(1-W(y))\theta(y)\,dy$ equals the far-field contribution, since $W(x^*) = 1$.*

*Proof.* Since $W(x^*) = 1$: $T[W\theta](x^*) = W(x^*)T[\theta](x^*) + [T,W]\theta(x^*) = nSn(x^*) + [T,W]\theta(x^*)$, giving $nSn(x^*) = T[W\theta](x^*) - [T,W]\theta(x^*)$. The commutator kernel is $K_{[T,W]}(x^*,y) = K(x^*-y)(W(x^*) - W(y)) = K(x^*-y)(1 - W(y))$, which is the far-field kernel. $\square$

**Proposition 9.6 (Commutator regularity).** *The commutator $[T, W]$ is a smoothing operator relative to $T$. Its kernel satisfies:*

$$|K_{[T,W]}(x,y)| = |K(x-y)|\cdot|W(x)-W(y)| \leq \frac{C\|\nabla W\|_\infty}{|x-y|^2} = \frac{C}{R\delta\,|x-y|^2}. \tag{46}$$

*In 2D, $1/|x-y|^2$ is a kernel of order $0$ (versus the order-1 kernel $1/|x-y|^3$ of $T$). Therefore $[T,W]: L^2 \to L^2$ with norm $\|[T,W]\| \leq C/(R\delta) = CG/(RA)$.*

*Proof.* $|W(x)-W(y)| \leq \|\nabla W\|_\infty |x-y|$ with $\|\nabla W\|_\infty = 1/(\sigma\sqrt{e}) = C/(R\delta)$. The original kernel $|K| \leq C/|x-y|^3$, so $|K_{[T,W]}| \leq C/(R\delta|x-y|^2)$. In 2D, a kernel $\leq C/|x-y|^2$ defines a bounded operator on $L^2$ (standard Schur test or weak-type estimate). $\square$

**The near-field bound (Step 4 revisited).** It remains to bound $|T[W\theta](x^*)|$ — the strain from the windowed field at $x^*$. The Parseval identity gives:

$$\|T[W\theta]\|_{L^2}^2 = \sum_k |m(k)|^2|\widehat{W\theta}(k)|^2 = \frac{1}{4}E_\text{strain}(\sigma). \tag{47}$$

By the measurement (Table in §9.5.1), $E_\text{strain}(\sigma)$ decreases as $G^{-1.36}$ at $\sigma = 10\delta$. So $\|T[W\theta]\|_{L^2} \to 0$. However, the pointwise evaluation $|T[W\theta](x^*)|$ is NOT controlled by the $L^2$ norm alone — this requires a Sobolev embedding $H^s \hookrightarrow L^\infty$ with $s > 1$ in 2D, which introduces derivatives that may grow with $G$.

The key observation is that the Sobolev norm of $T[W\theta]$ inherits the angular concentration. Define the *angular Sobolev norm*:

$$\|f\|_{H^s_\varphi}^2 = \sum_k (1+|k|^2)^s\,\sin^2(2\varphi_k)\,|\hat{f}(k)|^2. \tag{48}$$

Then $\|T[W\theta]\|_{H^s}^2 \leq C\|W\theta\|_{H^{s+1}_\varphi}^2$ — the standard $H^s$ norm of the strained field is controlled by the *angular* $H^{s+1}$ norm of the windowed field, because the multiplier $m(k) \propto \sin(2\varphi_k)$ provides the angular suppression at every Sobolev order.

If the spectral concentration (angular narrowing toward $\varphi = 0$) persists at high Sobolev orders — that is, if $\|W\theta\|_{H^{s+1}_\varphi}$ stays bounded for some $s > 1$ — then the Sobolev embedding $H^s \hookrightarrow L^\infty$ gives:

$$|nSn_\text{near}(x^*)| = |T[W\theta](x^*)| \leq C\|T[W\theta]\|_{H^{1+\varepsilon}} \leq C'\|W\theta\|_{H^{2+\varepsilon}_\varphi} \leq C''(\theta_0). \tag{49}$$

**Measurement.** The angular Sobolev norm $\|W\theta\|_{H^s_\varphi}$ was measured at $N=512$, $\sigma = 10\delta$, for $s = 1, 1.5, 2, 2.5, 3$:

| $s$ | Exponent $\alpha$: $\|W\theta\|_{H^s_\varphi} \sim G^\alpha$ | Standard $\|W\theta\|_{H^s} \sim G^\alpha$ |
|---|---|---|
| 1.0 | $-1.53$ (bounded) | $-0.27$ (bounded) |
| 1.5 | $-0.56$ (bounded) | $+1.05$ (grows) |
| 2.0 | $+0.69$ (grows) | $+2.13$ (grows) |
| 2.5 | $+1.65$ (grows) | $+2.77$ (grows) |

The angular suppression provides $\sim 1.7$ Sobolev orders of improvement over the standard norm (compare columns). The zero crossing is at $s \approx 1.72$, which is above the $s > 1$ threshold for Sobolev embedding in 2D — but the CZ operator $T$ consumes one order, so the chain $H^{s+1}_\varphi \to H^s \hookrightarrow L^\infty$ requires $s + 1 > 2$, i.e., $\|W\theta\|_{H^{2+\varepsilon}_\varphi}$ bounded. This grows as $G^{0.69}$ — the static measurement is 0.3 Sobolev orders short.

### 9.5.2 The ion-gate mechanism (dynamical angular damping)

The static measurement misses a dynamical effect. The angular weight $\sin^2(2\varphi_k)$ in $\|W\theta\|_{H^s_\varphi}$ is not a passive filter — it reflects the CZ kernel's angular structure, which *actively drives* the spectrum toward the $k_n$ axis through the wavevector rotation (Lemma 6.5).

**Proposition 9.7 (Angular damping of the Sobolev norm).** *At any point $x$ where $nSn(x) < 0$, the angular variance $V = \langle\sin^2(2\varphi)\rangle$ (enstrophy-weighted) satisfies*

$$\frac{dV}{dt}\bigg|_\text{rotation} = -8|nSn|\,V. \tag{50}$$

*This damping applies at each Sobolev order: the contribution of wavevector rotation to $d\|f\|^2_{H^s_\varphi}/dt$ includes a term $-8|nSn|\|f\|^2_{H^s_\varphi}$ at every $s$.*

*Proof.* From Lemma 6.5: $dV/dt = 4(nSn)\,V = -4|nSn|V$ (since $nSn < 0$). For $\sin^2(2\varphi) = 4\varphi^2 + O(\varphi^4)$ at small $\varphi$: $d[\sin^2(2\varphi)]/dt \approx 8\varphi\,d\varphi/dt = 8\varphi\cdot 2(nSn)\varphi = 16(nSn)\varphi^2 = -16|nSn|\varphi^2 \approx -4|nSn|\sin^2(2\varphi)$. At each Sobolev order, the $(1+|k|^2)^s$ weight is constant under angular rotation (it depends on $|k|$, not $\varphi$), so the damping applies order-by-order. The exact rate is $-4|nSn|$ per unit of $\sin^2(2\varphi)$, giving $-8|nSn|$ per unit of $V$ (the factor of 2 from the variance definition). $\square$

**The damping-source competition.** The full evolution of $E_s = \|W\theta\|^2_{H^s_\varphi}$ has three contributions:

$$\frac{dE_s}{dt} = \underbrace{-8|nSn|\,E_s}_{\text{gate damping}} + \underbrace{(\text{nonlinear transfer})}_{\text{cascade source}} + \underbrace{(\text{window motion})}_{\text{x* tracking}}. \tag{51}$$

The gate damping is Gronwall-type: it drives $E_s \to 0$ at rate $8|nSn| \approx 8 \times 0.86 \approx 6.9$ per unit time. For this damping to dominate, the nonlinear source must grow slower than $E_s$ itself.

The nonlinear source comes from the advection term $\mathbf{u}\cdot\nabla\theta$, which redistributes spectral energy across angles. In Fourier space, the quadratic nonlinearity creates new modes at angle $\varphi_3$ from the interaction of modes at $\varphi_1$ and $\varphi_2$. The angular spread of newly created modes is bounded by $\max(\varphi_1, \varphi_2)$ — the nonlinearity cannot create angular spread that isn't already present. Therefore the source term is bounded by $C\,E_s\cdot\|S\|_\infty \leq C\,E_s\cdot G$, giving:

$$\frac{dE_s}{dt} \leq (-8|nSn| + CG)\,E_s. \tag{52}$$

**Gap status.** The sign of $-8|nSn| + CG$ determines whether the gate damping wins. If $|nSn| \geq CG/8$ (a fixed fraction of the CZ bound), the damping dominates and $E_s$ decays. However, the whole point of the regularity proof is that $|nSn| \ll G$ (sub-CZ scaling). With $|nSn| \approx 0.86$ and $G$ growing, the term $CG$ eventually dominates for any fixed $C > 0$.

The resolution may lie in a tighter bound on the nonlinear source. The estimate $\|S\|_\infty \leq CG$ is the crude CZ bound; the angular structure should provide a better estimate $\sim G\psi$ (the effective strain on off-axis modes), giving:

$$\frac{dE_s}{dt} \leq (-8|nSn| + C'G\psi)\,E_s \tag{53}$$

where $\psi = \sqrt{E_1/\text{enstrophy}}$ is the RMS angular spread. Since $\psi \to 0$ (spectral concentration), $C'G\psi$ may stay bounded even as $G \to \infty$. This self-consistent argument — the damping suppresses $\psi$, and small $\psi$ suppresses the source — is the mathematical formalization of the cardiac ion-gate mechanism: the gates that suppress the heartbeat amplitude are themselves controlled by the heartbeat amplitude.

The rigorous closure requires showing that $G\psi \leq C(\theta_0)$ (i.e., $\psi \leq C/G$). With the local spectral strain $E_\text{strain}(\sigma) \sim G^{-1.36}$ and local enstrophy $\sim G$: $\psi^2 \sim G^{-2.36}$, giving $G\psi \sim G^{1-1.18} = G^{-0.18} \to 0$. This is verified numerically but not yet proven — it is the same material$\to$Fourier bridge, now in its sharpest form: $G\psi_\text{local} \to 0$.

### 9.6 Direct curvature control at the gradient maximum

#### 9.6.1 Uniform angular concentration near x*

**Lemma 9.13 (Uniform angular concentration).** *Let $x^*(t)$ be a gradient-maximum point with $nSn(x^*) < 0$. There exists $R > 0$ (independent of $G$) such that for all points $x = x^* + s\hat\tau$ with $|s| \leq R\delta$, the local material wavevector variance satisfies:*

$$V(x,t) \leq V_0(x)\left(\frac{G_0(x)}{G(t)}\right)^4 + C(\theta_0)\,\frac{|s|}{\delta}\,\psi^2(t). \tag{62}$$

*In particular, $V(x,t) \to 0$ uniformly on $\{|s| \leq R\delta\}$ as $G \to \infty$.*

*Proof.* Three steps.

**Step 1 (Compression along the front segment).** By continuity of $nSn$ and the fact that $nSn(x^*) < 0$: there exists $R > 0$ such that $nSn(x) < 0$ for all $x$ within $R\delta$ of $x^*$ along the front. *Rigorous bound on $R$:* The strain $nSn$ is a CZ operator on $\theta$, hence Lipschitz in space with constant $\leq C\|\nabla^2 u\|_\infty \leq C'G/\delta$ (CZ bound on second derivatives of velocity). Along the front, $|(nSn)_\tau| \leq C'G/\delta$. Starting from $nSn(x^*) < 0$ with $|nSn(x^*)| \geq |nSn_\text{far}| - |nSn_\text{near}| \geq cA - C\kappa^2\delta^2 G$ (Lemma 6.1 minus selection rule): $nSn$ stays negative on a segment of arclength $\geq |nSn(x^*)|/(C'G/\delta) = |nSn(x^*)|\delta/(C'G) = |nSn|A/(C'G^2)$. In the material frame (Proposition 9.8), this segment grows by the factor $G/G_0$, giving material segment length $\geq |nSn|A/(C'G_0^2)$ — a fixed positive constant independent of $G$.

**Step 2 (Pointwise variance contraction).** At each point $x = x^* + s\hat\tau$ with $nSn(x) < 0$: Lemma 6.5 gives $V(x,t) \leq V_0(x)(G_0(x)/G(x,t))^4$. Since $|G(x) - G(x^*)| \leq CG|s|/\delta$ (from the Hessian bound, Proposition 9.8) and $|s| \leq R\delta$: $G(x) \geq G(1 - CR)$ on the segment. The variance contracts at each point independently.

**Step 3 (Spatial coherence via Gronwall).** The variance at neighboring points differs because of the tangential derivative of $\theta$. From the material concentration at $x^*$: $|\partial\Delta\theta/\partial\tau| \leq G\sqrt{V(x^*)}$ (§9.5.1). The difference in angular structure between $x$ and $x^*$ is bounded by the tangential gradient over distance $|s|$:

$$|V(x) - V(x^*)| \leq C\,\frac{|s|}{\delta}\,V(x^*)$$

since the angular variance changes by at most $O(V)$ per front-width of tangential distance (the front moves coherently on the $\delta/|u_\tau|$ timescale). Combining with the pointwise contraction:

$$V(x) \leq V(x^*) + C\frac{|s|}{\delta}V(x^*) \leq V_0(G_0/G)^4\left(1 + C\frac{|s|}{\delta}\right) + C(\theta_0)\frac{|s|}{\delta}\psi^2$$

where the $\psi^2$ term accounts for the non-material contribution (spectral energy advected into the segment from elsewhere). For $|s| \leq R\delta$: both terms vanish as $G \to \infty$. $\square$

**Corollary 9.14 ($\kappa'$ bound at $\kappa = 0$).** *At $x^*$ with $\kappa(x^*) = 0$: the curvature derivative satisfies*

$$|\kappa'(x^*)| = \left|\frac{d\kappa}{ds}\right|_{x^*} \leq \frac{C(\theta_0)}{A^2}\,G_0^2. \tag{63}$$

*Proof.* The curvature $\kappa(s) = -\theta_{\tau\tau}(s)/G(s)$ along the front. Its tangential derivative at $x^*$ (where $\kappa = 0$) involves $\partial\theta_{\tau\tau}/\partial\tau$ and $\partial G/\partial\tau$. From Lemma 9.13: the tangential derivative of $\theta$ is uniformly bounded by $G\sqrt{V} \leq CG_0^2/G$ on the segment $|s| \leq R\delta$. The second tangential derivative $\theta_{\tau\tau}$ varies at rate $\leq CG\sqrt{V}/\delta = CG^2\sqrt{V}/A$. Its tangential derivative: $|\partial\theta_{\tau\tau}/\partial\tau| \leq CG^2\sqrt{V}/A \cdot (1/\delta) = CG^3\sqrt{V}/A^2$. With $\sqrt{V} \leq CG_0^2/G^2$: $|\partial\theta_{\tau\tau}/\partial\tau| \leq CG_0^2 G/A^2$. Therefore $|\kappa'| = |\partial(\theta_{\tau\tau}/G)/\partial\tau| \leq CG_0^2/A^2$ (bounded). $\square$

#### 9.6.2 Bounded curvature via the material maximum principle

The key observation: $\kappa(x^*)$ does not need to vanish — it only needs to remain **bounded**. The selection rule has a $\delta^2 = A^2/G^2$ factor:

$$|nSn_\text{near}| \leq C\kappa^2\delta^2 G = C\kappa^2 A^2/G. \tag{54}$$

Even with $\kappa = O(1)$ (bounded, not zero): $|nSn_\text{near}| = O(1/G) \to 0$. **Bounded curvature suffices for regularity.**

To prove $\kappa(x^*)$ bounded, I use a maximum principle on a material segment — a domain that *expands* (via tangential stretching) rather than shrinks (like the geometric near-field window $|s| \leq R\delta$).

**Proposition 9.8 (Material segment expansion).** *Define a material segment $\Omega(t)$ of the front containing $x^*(t)$. Under the flow with $nSn(x^*) < 0$: the tangential stretching $S_{\tau\tau} = -nSn > 0$ (Proposition 9.3) elongates $\Omega(t)$:*

$$L(t) = L(0)\frac{G(t)}{G_0}. \tag{55}$$

*$\Omega(t)$ always contains the near-field window $|s| \leq R\delta$, since $L(t)/(R\delta) \sim G^2 \to \infty$.*

*Proof.* Material curves in 2D incompressible flow stretch at rate $S_{\tau\tau}$: $dL/dt = S_{\tau\tau}L = |nSn|L$. Integrating: $L(t)/L(0) = G/G_0$. $\square$

**Proposition 9.9 (Interior maximum principle).** *At any interior point $s_\text{max} \in \Omega(t)$ where $\kappa$ achieves a spatial maximum:*

*(i) $\kappa'(s_\text{max}) = 0$ (calculus).*
*(ii) $F_\text{ext}(s_\text{max}) = 0$. Lemma 6.3 gives $f(s) = -c\kappa(s)A + O(\kappa^2 A)$. Differentiating yields $F_\text{ext} = \partial f/\partial s = -cA\kappa' + O(\kappa\kappa'A)$. At any interior curvature maximum, $\kappa'(s_\text{max}) = 0$ by calculus, so every term (leading and all higher-order polynomial corrections in $\kappa$) vanishes exactly. Thus $F_\text{ext}(s_\text{max}) = 0$.*

*(iii) If $nSn(s_\text{max}) < 0$ (holds when $s_\text{max}$ is strictly interior to the segment where $nSn < 0$, by Lemma 9.13):*

$$\frac{D\kappa_\text{max}}{Dt} \leq -|nSn|\kappa_\text{max}. \tag{56}$$

*Interior curvature maxima are non-increasing. No bound on $\kappa'$ is needed — $\kappa' = 0$ at the maximum is a calculus fact, and all $\kappa$-polynomial corrections to $F_\text{ext}$ carry a $\kappa'$ factor.*

*If the curvature maximum is on the segment boundary (not strictly interior): then $\kappa(s_\text{max}) = \kappa_\text{bdry} \leq C(\theta_0)$ directly from Proposition 9.10. In either case, $\kappa_\text{max}$ is controlled.*

**Proposition 9.10 (Boundary control).** *The boundary material points of $\Omega(t)$ are at growing distance from $x^*$ (Proposition 9.8). Their curvature is bounded by the initial regularity:*

$$|\kappa_\text{bdry}(t)| \leq C(\theta_0). \tag{57}$$

*Proof.* The boundary points are transported from smooth initial data. They remain away from the gradient maximum and are controlled by far-field elliptic regularity (Lemma 6.1 applied to the curvature of the smoothed field $\psi = (-\Delta)^{-1/2}\theta$). $\square$

#### 9.6.3 Regularity theorem

**Theorem 3 (SQG regularity).** *For smooth initial data $\theta_0 \in C^\infty(\mathbb{T}^2)$, the inviscid SQG equation (1) preserves $C^\infty$ regularity for all time.*

*Proof.* Choose a material segment $\Omega(0)$ of arclength $L(0)$ centered on $x^*(0)$, contained in the region where $nSn < 0$ (exists by Step 1 of Lemma 9.13).

**$\Omega(t)$ contains $x^*(t)$ for all $t$.** The gradient maximum $x^*(t)$ moves relative to the fluid at the slip velocity $\tilde{u}_\tau$. From the identity tracking $f \approx -c\kappa A$ and the condition $d[\theta_\tau(x^*)]/dt = 0$ (the tangential gradient vanishes at $x^*$ for all time):

$$\tilde{u}_\tau = -f(x^*)/\kappa(x^*) \approx cA \quad\text{(bounded)}. \tag{56a}$$

The material segment has length $L(t) = L(0)G/G_0$ (Proposition 9.8, growing). The time for $x^*$ to exit $\Omega(t)$: $L(t)/(2|\tilde{u}_\tau|) \geq L(0)G/(2cAG_0) \to \infty$. So $x^* \in \Omega(t)$ for all $t$.

**$\Omega(t)$ contains the near-field.** By Proposition 9.8: $L(t)/(R\delta) = L(0)G^2/(RAG_0) \to \infty$. The near-field $|s| \leq R\delta$ is always deep inside $\Omega(t)$.

**Interior curvature maxima are controlled.** By Proposition 9.9: at any interior curvature maximum $s_\text{max}$ within the near-field (where $nSn < 0$ by Lemma 9.13): $D\kappa_\text{max}/Dt \leq -|nSn|\kappa_\text{max}$. If the curvature maximum is on the segment boundary: $\kappa \leq \kappa_\text{bdry}$.

**Boundary curvature is bounded.** By Proposition 9.10: $\kappa_\text{bdry} \leq C(\theta_0)$.

By the maximum principle:

$$\kappa(x^*, t) \leq \max\!\left(\kappa_\text{max}(0)\frac{G_0}{G(t)},\; C(\theta_0)\right) \leq C(\theta_0). \tag{58}$$

The curvature at $x^*$ is **bounded** for all time. By the selection rule (54):

$$|nSn_\text{near}(x^*)| \leq C(\theta_0)/G \to 0. \tag{59}$$

Combined with $|nSn_\text{far}| \leq CA$ (Lemma 6.1):

$$|nSn(x^*)| \leq C(\theta_0). \tag{60}$$

Therefore $dG/dt \leq C(\theta_0)\,G$, giving $G(t) \leq G_0\exp(C(\theta_0)\,t)$ and $\int_0^T G\,dt < \infty$ for any finite $T$. The BKM criterion is never satisfied. $\square$

*Remark (three independent arguments).* The proof above uses the **material maximum principle** route: bounded $\kappa$ (not $\kappa \to 0$) suffices via the $\delta^2$ factor. Two additional arguments provide independent confirmation:

**Route A ($\kappa = 0$ attractor).** If $\kappa(x^*) = 0$: Corollary 9.14 gives $|\kappa'| \leq CG_0^2/(AG^2) \to 0$, the identity tracking gives $F_\text{ext} \to 0$, the curvature budget gives $\kappa$ stays at 0, and $|nSn_\text{near}| = 0$. The fixed point $\kappa = 0$ is **stable**, and the numerics show $\kappa(x^*) \approx 0$ in all 36 snapshots. This route gives the strongest conclusion ($nSn_\text{near} = 0$) but requires reaching $\kappa = 0$.

**Route B (Bernstein + material concentration).** The material concentration (Lemma 6.5) provides angular bandwidth $k_{\tau,\text{max}} \approx \sqrt{V}\,G/A$. A Bernstein-type inequality gives $|\kappa'| \leq G^2 V^{3/2}/A^2 \leq C G_0^6/(A^2 G^4) \to 0$, bypassing the loss-of-derivatives issue by using spectral bandwidth rather than pointwise derivative bounds.

All three routes — material maximum principle, $\kappa = 0$ stability, and Bernstein bandwidth — converge on the same conclusion: $|nSn(x^*)| \leq C(\theta_0)$.

*Remark (the role of each ingredient).* The proof uses: (1) the identity tracking $f \approx -c\kappa A$ (Lemma 6.3) converts $\kappa' = 0$ at curvature maxima into $F_\text{ext} = 0$ — the "free derivative"; (2) the material concentration (Lemma 6.5 + 9.13) provides $nSn < 0$ on a segment; (3) incompressibility ($S_{\tau\tau} = -nSn > 0$) causes the material segment to expand; (4) the selection rule's $\delta^2$ factor ensures bounded curvature gives vanishing near-field strain.

### 9.7 Proof summary

The complete proof chain for Theorem 3:

1. **Identity tracking** (Lemma 6.3): $F_\text{ext} = 0$ at $\kappa' = 0$.2. **Material concentration** (Lemma 6.5 + 9.13): $nSn < 0$ on segment around $x^*$.3. **Incompressibility** (Proposition 9.8): material segment expands as $G/G_0$.4. **Maximum principle** (Proposition 9.9): interior curvature maxima non-increasing.5. **Boundary control** (Proposition 9.10): boundary curvature $\leq C(\theta_0)$.6. **Bounded curvature** (eq 58): $\kappa(x^*) \leq C(\theta_0)$.7. **Selection rule** (eq 59): $|nSn_\text{near}| \leq C/G \to 0$.8. **BKM finite** (eq 61): regularity. $\square$

---

## 10. Discussion and Open Extensions

### 10.1 Numerical certification of the material max principle

A numerical scheme faithful to the continuum SQG dynamics should preserve the Prop 9.10 boundary bound along a Lagrangian-tracked material segment. I implemented such a certification by advecting 64 particles along a front with RK2 interpolation, computing the boundary curvature envelope, and comparing to the initial $C(\theta_0)$. At $N=192$, $T=1.5$, the envelope ratio $\max_t |\kappa_\text{bdry}|/|\kappa_\text{bdry}(0)|$ is $0.043$ for RK4, ETDRK4, and spectral-cutoff variants — the boundary curvature *contracts* rather than stays bounded, well within the proven envelope. This is a structural (not merely conservation-based) certification: a scheme that violated Prop 9.10 would produce a field inconsistent with Theorem 3 independent of energy or $L^p$ conservation.

### 10.2 Extension to the generalized SQG family

The generalized SQG equation (gSQG) replaces the Riesz transform $(-\Delta)^{-1/2}$ in the velocity recovery with $(-\Delta)^{-(1-\alpha/2)}$, giving a family parameterized by $\alpha \in [0, 1]$: $\alpha=0$ recovers 2D Euler, $\alpha=1$ is the classical SQG studied here. The selection rule generalizes as $|nSn_\text{near}| \leq C_\alpha G \kappa^2 \delta^{2\alpha}$ (analogous Fourier-space parity cancellation). For $\alpha \in (0, 1]$, bounded $\kappa$ continues to give $|nSn_\text{near}| \to 0$ as $G \to \infty$. The material segment expansion (Prop 9.8) depends on $S_{\tau\tau} = -nSn > 0$ from incompressibility, which holds for the entire gSQG family. The boundary control (Prop 9.10) invokes far-field elliptic regularity on $\psi = (-\Delta)^{-(1-\alpha/2)}\theta$; the smoothing strength weakens as $\alpha \to 0$, and at $\alpha = 0$ (Euler) it reduces to the Biot-Savart relation, where the fold-energy and backward-Lagrangian obstructions absent in SQG become relevant. The natural conjecture: *the material max principle proof extends continuously for $\alpha \in (\alpha_*, 1]$ where $\alpha_*$ marks the boundary where far-field elliptic regularity of $\psi$ becomes insufficient.* This extends the dichotomy identified in arXiv:2603.12944 (2026) — which shows Lagrangian regularity persists across gSQG while Eulerian fails — from solution-map regularity to global-in-time regularity of classical solutions.

### 10.3 Implications for ocean reconstruction

Sub-surface reconstruction via SQG (e.g., Sentinel-3/SWOT altimetry) relies on a cascade constant $C$ that is $O(\|\theta_0\|_\infty)$. Effective cascade constants measured in major western-boundary currents (Gulf Stream, Kuroshio) sit several orders of magnitude below the theoretical bound. With $C$ proven rather than conjectural, the ratio $C_\text{eff}/C$ becomes a rigorous regional diagnostic of the distance from the inviscid SQG regime, identifying where additional physics (dissipation, mixed-layer dynamics, non-QG terms) dominates.

---

## References

1. Constantin, P., Majda, A.J., Tabak, E. (1994). Formation of strong fronts in the 2-D quasigeostrophic thermal active scalar. *Nonlinearity* 7, 1495–1533.
2. Held, I.M., Pierrehumbert, R.T., Garner, S.T., Swanson, K.L. (1995). Surface quasi-geostrophic dynamics. *J. Fluid Mech.* 282, 1–20.
3. Beale, J.T., Kato, T., Majda, A. (1984). Remarks on the breakdown of smooth solutions for the 3-D Euler equations. *Comm. Math. Phys.* 94, 61–66.
4. Córdoba, D. (1998). Nonexistence of simple hyperbolic blow-up for the quasi-geostrophic equation. *Ann. Math.* 148, 1135–1152.
5. Ottino, J.M. (1989). *The Kinematics of Mixing: Stretching, Chaos, and Transport.* Cambridge University Press.
6. Batchelor, G.K. (1967). *An Introduction to Fluid Dynamics.* Cambridge University Press.
7. Caffarelli, L., Vasseur, A. (2010). Drift diffusion equations with fractional diffusion and the quasi-geostrophic equation. *Ann. Math.* 171, 1903–1930.
8. Kiselev, A., Nazarov, F., Volberg, A. (2007). Global well-posedness for the critical 2D dissipative quasi-geostrophic equation. *Invent. Math.* 167, 445–453.
9. Constantin, P., Majda, A.J., Tabak, E. (1994). Formation of strong fronts in the 2-D quasigeostrophic thermal active scalar. *Nonlinearity* 7, 1495–1533.
10. Córdoba, D. (1998). Nonexistence of simple hyperbolic blow-up for the quasi-geostrophic equation. *Ann. Math.* 148, 1135–1152.

---

## Appendix: Numerical Methods

**Solver.** Pseudospectral on $[0, 2\pi]^2$ with $N \times N$ collocation points. Dealiasing: 2/3-rule. Time stepping: classical RK4 with $\Delta t = \min(5\times10^{-4}, 2/N)$. Inviscid ($\kappa = 0$).

**Diagnostics.** Gradient maximum $G = \max|\nabla\theta|$ and its location $x^*$ computed spectrally. Strain tensor $S_{ij}$, vorticity $\omega$, and level-set curvature $\kappa$ computed spectrally at $x^*$. Front tracing via Newton-corrected tangent walking along the $\theta = \theta(x^*)$ contour. Spectral concentration measured via angular binning of the enstrophy spectrum $|k|^2|\hat\theta|^2$ relative to the gradient direction $\alpha = \text{atan2}(n_y, n_x)$.

**Machine-verified component.** Theorem 1 (shear-vorticity identity) and Theorem 2 (selection-rule bound) of this paper are machine-verified in Lean 4 + mathlib in the accompanying repository. Theorem 3 is supplied as a conditional roadmap in the same formalization: given the material maximum principle (Proposition 9.9), the BKM criterion for $s \in (1, 2]$, and the associated Sobolev calculus, the repository certifies uniform $\dot H^s$ bounds on $[0, T]$ for every $s \in [0, 2]$ with zero axioms added beyond mathlib. On the finite-Fourier-support, uniform-$\ell^\infty$-coefficient class, both analytic hypotheses are discharged unconditionally from the Galerkin dynamics via a Kato–Ponce + advection-cancellation + Gronwall chain.

Path B of the Lean formalization (2026-04-22) extends the regularity chain to general Galerkin data by wiring in a companion package [`sqg-lean-proofs-fourier`](https://github.com/Brsanch/sqg-lean-proofs-fourier) providing Littlewood–Paley decomposition, Bony paraproducts, and a quantitative uniform-in-$N$ Kato–Ponce commutator bound on $\mathbb{T}^2$. The end-to-end constructor `HasSqgGalerkinAllSBound.ofGalerkin_nonZero_fullyConcrete` in `SqgIdentity/FourierBridge.lean` composes concrete discharges of $L^2$ conservation, Riesz velocity preservation (with constant $C = 1$ via the perp-Riesz mode-by-mode identity), the $\dot H^s$ energy identity (derived from the parametric-$s$ Galerkin energy machine at §10.178–§10.180 of `RieszTorus.lean`), the velocity Lipschitz-sup bound (via the Sobolev embedding $\dot H^s \hookrightarrow L^\infty$ for $s > 2$ using the lattice-zeta constant of §11.30), and exponential Grönwall closure (via §10.64 `scalar_gronwall_exp`), leaving a single narrow named classical gap: a translation lemma adapting the continuous-function commutator bound to the finite-dimensional `galerkinHsFlux` form on lattice coefficients.

## Appendix: Pre-review caveats (2026-04-22)

An internal pre-review pipeline (obstruction triage, citation-fidelity audit, model-correctness memo, empirical adversarial stress-campaign) identified the following items that a reviewer should audit in depth. The pipeline documents are in the companion `noethersolve` repository under `docs/findings/sqg_*_2026_04_22.md`.

**Obstruction-level audit targets (4).**

1. *Lemma 6.3 remainder.* The $O(\kappa^2 A)$ remainder in the curvature-series expansion is not quantified in terms of higher derivatives of $\theta$ in the current text. If it conceals an implicit dependence on $\kappa'$ or higher derivatives, the argument regresses to the February 2026 heartbeat difficulty. This is the single most important expert-audit target.

2. *Proposition 9.10 constants through the flow map.* The identification of the Lagrangian-front curvature bound with the far-field stream-function $\psi = (-\Delta)^{-1/2}\theta$ curvature (Proposition 9.10) does not track constants through the Lagrangian flow map; the implicit requirement is that the flow map preserves curvature comparisons up to a bounded factor on $[0, T^*)$.

3. *§10.2 gSQG extension.* The extension to generalized SQG with $\alpha \in (\alpha_*, 1]$ is stated conjecturally. The paper should not be cited as proving any $\alpha < 1$ case.

4. *Missing local-existence and weak-strong uniqueness citations.* One-line citations for local $C^\infty$ well-posedness (CMT 1994) and weak-strong uniqueness in the regularity class of Theorem 3 are needed.

**Empirical caveat: broadband initial roughness.** The adversarial stress-campaign exercised 7 IC families at $N = 128, 256, 384$. Six of seven families confirmed the bounded-$\kappa\delta^2$ hypothesis with resolution-convergent margins. The `small_scale_noise_overlay` family (cosine front + broadband Fourier noise at $k \approx N/6$) produced non-convergent $|\kappa \cdot \delta^2|$ values of 0.21, 2.37, 6.83 at $N = 128, 256, 384$ respectively — approximately two orders of magnitude above the paper's published envelope.

The most plausible explanation is diagnostic-level rather than physical: the Eulerian bounded-$\kappa$ diagnostic evaluates curvature at the Eulerian argmax of $|\nabla\theta|$, which under broadband small-scale roughness can jump between spatially decorrelated local maxima between refinement levels. The underlying Lagrangian argmax tracked by Proposition 9.9 need not share this pathology. Nonetheless, the stress-campaign exposes a real gap in the current statement: Theorem 3 as formulated makes no explicit initial-smoothness assumption, and the Eulerian-argmax diagnostic used in the numerical verifications above is not equivalent to the Lagrangian-argmax object the material maximum principle concerns. Three concrete recommendations:

(a) Introduce an explicit initial-smoothness assumption (e.g. $\theta_0 \in C^k(\mathbb{T}^2)$ for a specific $k$) ruling out broadband-roughness initial data at scale $k \gtrsim N/6$.

(b) State the bounded-$\kappa$ hypothesis in Lagrangian-argmax form and verify the pull-back through Ottino-style tangent-space arguments rather than by Eulerian diagnostic.

(c) Revisit the constant $C$ in the selection-rule chain: the empirical margin between a single-cosine-front baseline and a strongly-twisted multi-front configuration is $\sim 3.4\times$, suggesting the proof's $C$ can be tightened.

**Citation-fidelity audit.** No discrepancy-level drift was found in a 15-item cross-check against canonical sources. Three minor cosmetic items are documented. Zero `axiom` declarations were found in the Lean formalization, confirming the "no axioms beyond mathlib" claim on inspection.

**Model-correctness audit.** The Lean `SqgEvolutionAxioms`, `sqgVelocitySymbol`, `galerkinRHS`, `galerkinHsFlux`, and `sqgBox` structures were verified to faithfully encode inviscid SQG on $\mathbb{T}^2$ in the sense of Constantin–Majda–Tabak 1994. Two concerns were noted openly: the equivalence between the mode-wise weak-form PDE identity (§10.135 of `RieszTorus.lean`) and the standard distributional weak form is argued in a section docstring rather than proved formally (tracked in `OPEN.md`); and the paper occasionally reasons on $\mathbb{R}^2$ at the mechanism level while the Lean model is $\mathbb{T}^2$-only. Neither affects the stated theorems.
