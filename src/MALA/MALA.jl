module MALA

using Random, LinearAlgebra

# Preconditioner dispatch helpers.  cholM is either nothing (identity) or a Cholesky factor.
_apply_M(g, ::Nothing) = g
_apply_M(g, cholM::Cholesky) = cholM.L * (cholM.L' * g)

_apply_L(ξ, ::Nothing) = ξ
_apply_L(ξ, cholM::Cholesky) = cholM.L * ξ

_quad_Minv(r, ::Nothing) = dot(r, r)
function _quad_Minv(r, cholM::Cholesky)
    w = cholM.L \ r
    return dot(w, w)
end

_logdet_M(::Nothing) = false  # Bool promotes to any numeric type without widening
_logdet_M(cholM::Cholesky) = logdet(cholM)

"""
Compute the log of the MALA proposal density q(y | x).

With mass matrix M (passed as `cholM = cholesky(M)`):
  y ~ Normal(x + ϵ M ∇logp(x), 2ϵ M)

With `cholM=nothing` (default), uses identity M = I.
"""
function logq_mala(
    y::AbstractVector, x::AbstractVector, gradlogp_x::AbstractVector, ϵ::Real; cholM=nothing
)
    T = typeof(ϵ)
    μ = x .+ ϵ .* _apply_M(gradlogp_x, cholM)
    d = length(x)
    r = y .- μ
    return -T(0.5) * _quad_Minv(r, cholM) / (2ϵ) - (T(d) / 2) * log(T(4π) * ϵ) -
           T(0.5) * _logdet_M(cholM)
end

"""
One taped MALA step.

Inputs:
- logp(x): log density (up to constant)
- gradlogp(x): gradient of log density
- x: current state
- ϵ: step size
- ξ: N(0, I) noise vector (tape)
- u: Uniform(0,1) scalar (tape)
- cholM: optional Cholesky factor of mass matrix M (default: identity)

Returns:
- x_next
"""
function mala_step_taped(
    logp, gradlogp, x::AbstractVector, ϵ::Real, ξ::AbstractVector, u::Real; cholM=nothing
)
    length(x) == length(ξ) || throw(DimensionMismatch("x and ξ must have the same length"))
    0.0 < u < 1.0 || throw(ArgumentError("u must be in (0, 1)"))
    g_x = gradlogp(x)

    y = x .+ ϵ .* _apply_M(g_x, cholM) .+ sqrt(2ϵ) .* _apply_L(ξ, cholM)

    logp_x = logp(x)
    logp_y = logp(y)

    g_y = gradlogp(y)
    logq_y_given_x = logq_mala(y, x, g_x, ϵ; cholM=cholM)
    logq_x_given_y = logq_mala(x, y, g_y, ϵ; cholM=cholM)

    logα = (logp_y + logq_x_given_y) - (logp_x + logq_y_given_x)

    return (log(u) < logα) ? y : x
end

"""
Run sequential taped MALA for T steps.

Inputs:
- x0: initial state
- ξs: vector of ξ_t noise vectors, length T
- us: vector of u_t uniforms, length T

Returns:
- xs: Vector of states length T+1, xs[1]=x0, xs[t+1]=x_t
"""
function run_mala_sequential_taped(
    logp,
    gradlogp,
    x0::AbstractVector,
    ϵ::Real,
    ξs::Vector{<:AbstractVector},
    us::AbstractVector;
    cholM=nothing,
)
    T = length(us)
    length(ξs) == T || throw(DimensionMismatch("ξs and us must have the same length"))
    xs = Vector{typeof(x0)}(undef, T + 1)
    xs[1] = copy(x0)
    x = copy(x0)
    for t in 1:T
        x = mala_step_taped(logp, gradlogp, x, ϵ, ξs[t], us[t]; cholM=cholM)
        xs[t + 1] = copy(x)
    end
    return xs
end

"Compute the MALA proposal map y = x + ϵ M ∇logp(x) + √(2ϵ) L ξ."
function mala_proposal(
    logp, gradlogp, x::AbstractVector, ϵ::Real, ξ::AbstractVector; cholM=nothing
)
    length(x) == length(ξ) || throw(DimensionMismatch("x and ξ must have the same length"))
    g_x = gradlogp(x)
    return x .+ ϵ .* _apply_M(g_x, cholM) .+ sqrt(2ϵ) .* _apply_L(ξ, cholM)
end

"Compute log acceptance ratio logα(x→y) for MALA."
function mala_logα(
    logp, gradlogp, x::AbstractVector, y::AbstractVector, ϵ::Real; cholM=nothing
)
    g_x = gradlogp(x)
    g_y = gradlogp(y)
    logp_x = logp(x)
    logp_y = logp(y)
    logq_y_given_x = logq_mala(y, x, g_x, ϵ; cholM=cholM)
    logq_x_given_y = logq_mala(x, y, g_y, ϵ; cholM=cholM)
    return (logp_y + logq_x_given_y) - (logp_x + logq_y_given_x)
end

"""
Primal accept indicator for a taped MALA step.
Returns a float in {0, 1} matching the precision of `u`, for use as a constant
gate in the DEER surrogate step.
"""
function mala_accept_indicator(
    logp, gradlogp, x::AbstractVector, ϵ::Real, ξ::AbstractVector, u::Real; cholM=nothing
)
    y = mala_proposal(logp, gradlogp, x, ϵ, ξ; cholM=cholM)
    logα = mala_logα(logp, gradlogp, x, y, ϵ; cholM=cholM)
    FP = typeof(float(u))
    return (log(u) < logα) ? one(FP) : zero(FP)
end

"""
One taped MALA step, returning both the next state and the accept flag.

This is the efficient entry point: it evaluates `gradlogp` exactly twice (once at `x`,
once at the proposal `y`), compared to calling `mala_accept_indicator` + `mala_step_taped`
separately which evaluates it five times.

Returns `(x_next, accepted::Bool)`.
"""
function mala_step_full(
    logp, gradlogp, x::AbstractVector, ϵ::Real, ξ::AbstractVector, u::Real; cholM=nothing
)
    x_next, accepted, _ = mala_step_with_logα(logp, gradlogp, x, ϵ, ξ, u; cholM=cholM)
    return x_next, accepted
end

"""
One taped MALA step, returning the next state, the accept flag, **and** the raw
log acceptance ratio `logα = log p(y) + log q(x|y) - log p(x) - log q(y|x)`.

The returned `logα` is the un-clamped value; the actual acceptance probability is
`min(1, exp(logα))`.  This is needed by adaptive step-size schemes (dual averaging).

Returns `(x_next, accepted::Bool, logα)`.
"""
function mala_step_with_logα(
    logp, gradlogp, x::AbstractVector, ϵ::Real, ξ::AbstractVector, u::Real; cholM=nothing
)
    length(x) == length(ξ) || throw(DimensionMismatch("x and ξ must have the same length"))
    0.0 < u < 1.0 || throw(ArgumentError("u must be in (0, 1)"))

    g_x = gradlogp(x)
    y = x .+ ϵ .* _apply_M(g_x, cholM) .+ sqrt(2ϵ) .* _apply_L(ξ, cholM)

    logp_x = logp(x)
    logp_y = logp(y)
    g_y = gradlogp(y)

    logq_y_given_x = logq_mala(y, x, g_x, ϵ; cholM=cholM)
    logq_x_given_y = logq_mala(x, y, g_y, ϵ; cholM=cholM)
    logα = (logp_y + logq_x_given_y) - (logp_x + logq_y_given_x)

    accepted = log(u) < logα
    x_next = accepted ? y : x
    return x_next, accepted, logα
end

"""
Stop-gradient surrogate step used for Jacobians (paper Section 3.2, eq. stop-gradient trick).

Uses a continuous sigmoid gate g = σ(logα − log u) so that AD can differentiate
through both the proposal direction *and* the acceptance probability:

    ∂x_t/∂x_{t-1} = g·J_proposal + (1−g)·I + σ′(g̃)·(∂logα/∂x)·(ỹ−x)ᵀ

Forward pass: `step_fwd` (`mala_step_taped`) still uses the exact binary accept/reject.
This function is called only inside DEER's Jacobian computation.

`u` enters via `DI.Constant` in `TapedRecursion`, so `log(u)` does not contribute
to the Jacobian — matching the stop-gradient on the acceptance threshold.
"""
function mala_step_surrogate_sigmoid(
    logp, gradlogp, x::AbstractVector, ϵ::Real, ξ::AbstractVector, u::Real; cholM=nothing
)
    y = mala_proposal(logp, gradlogp, x, ϵ, ξ; cholM=cholM)
    logα = mala_logα(logp, gradlogp, x, y, ϵ; cholM=cholM)
    g̃ = logα - log(u)
    g = one(g̃) / (one(g̃) + exp(-g̃))   # σ(g̃), no external dep on sigmoid
    return g .* y .+ (one(g) - g) .* x
end

# Apply mass matrix to a D×N matrix of gradient columns (same math as scalar,
# matrix multiply broadcasts naturally).
_apply_M_batched(G::AbstractMatrix, ::Nothing) = G
_apply_M_batched(G::AbstractMatrix, cholM::Cholesky) = cholM.L * (cholM.L' * G)

_apply_L_batched(Ξ::AbstractMatrix, ::Nothing) = Ξ
_apply_L_batched(Ξ::AbstractMatrix, cholM::Cholesky) = cholM.L * Ξ

"""
Compute column-wise M⁻¹-norm squared: `[||R[:,n]||²_{M⁻¹}]_n`.
`R` is D×N; returns a length-N vector.
GPU-compatible (uses `sum(abs2, …; dims=1)` which works on CuArrays).
Note: `cholM` must be `nothing` when using GPU arrays; the triangular solve
`cholM.L \\ R` pulls device arrays to CPU.
"""
function _quad_Minv_batched(R::AbstractMatrix, ::Nothing)
    return vec(sum(abs2, R; dims=1))
end

function _quad_Minv_batched(R::AbstractMatrix, cholM::Cholesky)
    W = cholM.L \ R
    return vec(sum(abs2, W; dims=1))
end

"""
    logq_mala_batched(Y, X, gradlogp_X, ε; cholM=nothing)

Compute `log q(Y[:,n] | X[:,n])` for all N chains simultaneously.
`Y`, `X`, `gradlogp_X` are D×N; returns a length-N vector.
"""
function logq_mala_batched(
    Y::AbstractMatrix, X::AbstractMatrix, gradlogp_X::AbstractMatrix, ε::Real; cholM=nothing
)
    T = typeof(ε)
    D = size(X, 1)
    μ = X .+ ε .* _apply_M_batched(gradlogp_X, cholM)
    R = Y .- μ
    q = _quad_Minv_batched(R, cholM)
    ldet = _logdet_M(cholM)
    return @. -T(0.5) * q / (2ε) - (T(D) / 2) * log(T(4π) * ε) - T(0.5) * ldet
end

"""
    mala_step_batched(logp_batch, gradlogp_batch, X, ε, Ξ, u; cholM=nothing)

Run one MALA step for N chains simultaneously.

- `X` :: D×N — current states (one chain per column).
- `Ξ` :: D×N — N(0,I) noise.
- `u` :: length-N — Uniform(0,1) draws.
- `logp_batch(X)` → length-N log-densities.
- `gradlogp_batch(X)` → D×N gradient matrix.

Returns `(X_next::AbstractMatrix, accepted::AbstractVector)`.

**GPU use:** pass `CuArray` inputs and GPU-compatible `logp_batch`/`gradlogp_batch`.
Requires `cholM=nothing` for full on-device execution (Cholesky preconditioner involves
a CPU-side triangular solve).  Use `eltype(X)` for `ε` to avoid float-type promotions
that would pull data off GPU.
"""
function mala_step_batched(
    logp_batch,
    gradlogp_batch,
    X::AbstractMatrix,
    ε::Real,
    Ξ::AbstractMatrix,
    u::AbstractVector;
    cholM=nothing,
)
    D, N = size(X)
    size(Ξ) == (D, N) || throw(DimensionMismatch("X and Ξ must have the same size"))
    length(u) == N || throw(DimensionMismatch("u must have length N = size(X,2)"))

    # Cast ε to element type of X to avoid float-promotion off GPU.
    ε_T = eltype(X)(ε)

    G_X = gradlogp_batch(X)                                                 # D×N
    Y =
        X .+ ε_T .* _apply_M_batched(G_X, cholM) .+
        sqrt(2 * ε_T) .* _apply_L_batched(Ξ, cholM)                      # D×N

    lp_X = logp_batch(X)                                                    # N
    lp_Y = logp_batch(Y)                                                    # N
    G_Y = gradlogp_batch(Y)                                                # D×N

    lq_YX = logq_mala_batched(Y, X, G_X, ε_T; cholM=cholM)                # N
    lq_XY = logq_mala_batched(X, Y, G_Y, ε_T; cholM=cholM)                # N

    logα = @. (lp_Y + lq_XY) - (lp_X + lq_YX)                            # N
    accepted = @. log(u) < logα                                             # N Bool

    # Select: proposal if accepted, current if rejected.
    # reshape to 1×N so it broadcasts against D×N.
    mask = reshape(accepted, 1, N)
    X_next = @. ifelse(mask, Y, X)                                          # D×N
    return X_next, vec(accepted)
end

"""
Explicit JVP (pushforward) of `mala_step_surrogate_sigmoid` w.r.t. `x`, evaluated in
the direction `v`.

Formula derivation (M = identity; generalises to mass matrix via the cholM kwargs):

    y(x)   = x + ε M ∇logp(x) + √(2ε) L ξ              (proposal)
    w      = y'(x)[v]  = v + ε M H(x)v                   (1st HVP at x)
    r      = x − y − ε M ∇logp(y)                        (backward residual)
    dr/dx  = v − w − ε M H(y)w                           (2nd HVP at y, in direction w)
    ∂logα  = ∇logp(y)·w − ∇logp(x)·v − r'M⁻¹dr/(2ε)
    ∂g     = g(1−g) ∂logα
    output = g w + (y−x) ∂g + (1−g) v

Note: ∂log q(y|x)/∂x = 0 because the forward residual y−μₓ = √(2ε)Lξ is constant in x.

Arguments:
- `hvp_fn(pt, dir)`: computes ∂gradlogp(pt)/∂pt · dir = H(pt) dir (one JVP of gradlogp).
"""
function mala_step_surrogate_sigmoid_jvp(
    logp,
    gradlogp,
    x::AbstractVector,
    ε::Real,
    ξ::AbstractVector,
    u::Real,
    v::AbstractVector,
    hvp_fn;
    cholM=nothing,
)
    #Forward pass
    g_x = gradlogp(x)
    y = x .+ ε .* _apply_M(g_x, cholM) .+ sqrt(2ε) .* _apply_L(ξ, cholM)
    g_y = gradlogp(y)
    logp_x = logp(x)
    logp_y = logp(y)
    logq_yx = logq_mala(y, x, g_x, ε; cholM=cholM)
    logq_xy = logq_mala(x, y, g_y, ε; cholM=cholM)
    logα = (logp_y + logq_xy) - (logp_x + logq_yx)
    g̃ = logα - log(u)
    g = one(g̃) / (one(g̃) + exp(-g̃))

    # 1st HVP: w = y'(x)[v] = v + ε M H(x)v 
    Hv_x = hvp_fn(x, v)
    w = v .+ ε .* _apply_M(Hv_x, cholM)

    # needed for derivative of backward residual 
    Hv_y = hvp_fn(y, w)

    r = x .- y .- ε .* _apply_M(g_y, cholM)          # backward residual
    dr = v .- w .- ε .* _apply_M(Hv_y, cholM)        # dr/dx[v]

    # Directional derivative of log-acceptance ratio
    # ∂log q(y|x)/∂x = 0; ∂log q(x|y)/∂x = −(1/2ε) M⁻¹r · dr
    Minv_r = isnothing(cholM) ? r : cholM \ r
    dlogα = dot(g_y, w) - dot(g_x, v) - inv(2ε) * dot(Minv_r, dr)

    # Assemble output JVP
    dg = g * (one(g) - g) * dlogα
    return g .* w .+ (y .- x) .* dg .+ (one(g) - g) .* v
end

"""
Fused MALA forward step and JVP of the sigmoid surrogate, sharing the primal computation.

Returns `(x_next, J·v)` where:
- `x_next` is from the exact forward step (binary accept/reject)
- `J·v` is the JVP of `mala_step_surrogate_sigmoid` at `(x, ε, ξ, u)` in direction `v`

Both results share a single evaluation of `gradlogp` at `x` and at the proposal `y`,
and a single evaluation of `logp` at `x` and `y`.  This halves the primal cost
relative to calling `mala_step_taped` and `mala_step_surrogate_sigmoid_jvp` separately.

Arguments:
- `hvp_fn(pt, dir)`: computes H(pt) dir = ∂gradlogp(pt)/∂pt · dir (one JVP of gradlogp).
"""
function mala_step_taped_and_jvp(
    logp,
    gradlogp,
    x::AbstractVector,
    ε::Real,
    ξ::AbstractVector,
    u::Real,
    v::AbstractVector,
    hvp_fn;
    cholM=nothing,
)
    length(x) == length(ξ) || throw(DimensionMismatch("x and ξ must have the same length"))
    0.0 < u < 1.0 || throw(ArgumentError("u must be in (0, 1)"))

    g_x = gradlogp(x)
    y = x .+ ε .* _apply_M(g_x, cholM) .+ sqrt(2ε) .* _apply_L(ξ, cholM)
    g_y = gradlogp(y)
    logp_x = logp(x)
    logp_y = logp(y)
    logq_yx = logq_mala(y, x, g_x, ε; cholM=cholM)
    logq_xy = logq_mala(x, y, g_y, ε; cholM=cholM)
    logα = (logp_y + logq_xy) - (logp_x + logq_yx)

    # Forward step: binary accept/reject 
    x_next = (log(u) < logα) ? y : x

    # JVP of sigmoid surrogate
    g̃ = logα - log(u)
    g = one(g̃) / (one(g̃) + exp(-g̃))

    Hv_x = hvp_fn(x, v)
    w = v .+ ε .* _apply_M(Hv_x, cholM)

    Hv_y = hvp_fn(y, w)
    r = x .- y .- ε .* _apply_M(g_y, cholM)
    dr = v .- w .- ε .* _apply_M(Hv_y, cholM)

    Minv_r = isnothing(cholM) ? r : cholM \ r
    dlogα = dot(g_y, w) - dot(g_x, v) - inv(2ε) * dot(Minv_r, dr)

    dg = g * (one(g) - g) * dlogα
    jvp_out = g .* w .+ (y .- x) .* dg .+ (one(g) - g) .* v

    return x_next, jvp_out
end


# ---------------------------------------------------------------------------
# Batched MALA: process all T time steps simultaneously (GPU-efficient).
#
# The sequential deer_update loop calls step_fwd/JVP T times per DEER
# iteration.  On GPU, T sequential kernel launches dominate wall time.
# The batched path below maps a D×T matrix of previous states to the
# next D×T matrix in one shot, replacing 6T gradient calls with ~8 batched
# calls (each over the full T-column matrix).
#
# JVP of the sigmoid surrogate is computed via central-difference FD:
#   JVP[z] ≈ (f_surr(x + h z) - f_surr(x - h z)) / (2h)
# This avoids nested AD and GPU-incompatible HVP computation.
# ---------------------------------------------------------------------------

"""
    _mala_surrogate_step_batched(logp_batch, gradlogp_batch, X, ε, Ξ, U; cholM=nothing)

Sigmoid-surrogate MALA step for N chains simultaneously.

- `X`  :: D×N — current states
- `Ξ`  :: D×N — N(0,I) noise
- `U`  :: N   — Uniform(0,1) draws

`logp_batch(X) -> N` and `gradlogp_batch(X) -> D×N` operate on the full matrix.

Returns `G .* Y + (1-G) .* X` (D×N) where G = sigmoid(logα - log u), the
differentiable approximation of the binary accept indicator.
"""
function _mala_surrogate_step_batched(
    logp_batch,
    gradlogp_batch,
    X::AbstractMatrix,
    ε::Real,
    Ξ::AbstractMatrix,
    U::AbstractVector;
    cholM=nothing,
)
    ε_T = eltype(X)(ε)
    sqrt2ε = sqrt(2 * ε_T)
    N = size(X, 2)

    G_X = gradlogp_batch(X)
    Y = X .+ ε_T .* _apply_M_batched(G_X, cholM) .+ sqrt2ε .* _apply_L_batched(Ξ, cholM)
    G_Y = gradlogp_batch(Y)
    Lp_X = logp_batch(X)
    Lp_Y = logp_batch(Y)
    LogQ_YX = logq_mala_batched(Y, X, G_X, ε_T; cholM=cholM)
    LogQ_XY = logq_mala_batched(X, Y, G_Y, ε_T; cholM=cholM)

    Logα = @. (Lp_Y + LogQ_XY) - (Lp_X + LogQ_YX)
    G̃ = @. Logα - log(U)
    G_sig = @. one(eltype(G̃)) / (one(eltype(G̃)) + exp(-G̃))
    G_row = reshape(G_sig, 1, N)
    return @. G_row * Y + (one(eltype(G_row)) - G_row) * X
end

"""
    mala_fwd_and_jvp_batched(logp_batch, gradlogp_batch, Xbar, ε, Ξ, U, Z; cholM, fd_step)

Batched forward step + Hutchinson Jacobian diagonal estimate for T chains.

**Arguments**
- `logp_batch(X::AbstractMatrix)` → length-T vector of log-densities.
- `gradlogp_batch(X::AbstractMatrix)` → D×T gradient matrix.
- `Xbar` :: D×T — previous states (Xbar[:,1] = s₀, Xbar[:,t] = S[:,t-1]).
- `ε`    :: step size.
- `Ξ`    :: D×T — noise tape.
- `U`    :: T   — uniform tape.
- `Z`    :: D×T — Rademacher probes (one per time step).
- `fd_step` — FD step h for surrogate JVP (default `cbrt(eps(eltype(Xbar)))`).

**Returns** `(FT, Jt)`:
- `FT` :: D×T — exact MALA transitions (binary accept/reject per column).
- `Jt` :: D×T — `Z .⊙ JVP_surrogate[Z]`, the Hutchinson diagonal estimate.

**How it works**: the JVP of the sigmoid surrogate w.r.t. xbar is approximated
by central differences:
    `JVP[z] ≈ (f_surr(Xbar + h z) - f_surr(Xbar - h z)) / (2h)`

This needs 2 extra `gradlogp_batch` calls (at Xbar±hZ) — each batched over all T
columns — replacing `6T` sequential per-step gradient calls with `~8` batched calls.
"""
function mala_fwd_and_jvp_batched(
    logp_batch,
    gradlogp_batch,
    Xbar::AbstractMatrix,
    ε::Real,
    Ξ::AbstractMatrix,
    U::AbstractVector,
    Z::AbstractMatrix;
    cholM=nothing,
    fd_step=nothing,
)
    ε_T = eltype(Xbar)(ε)
    sqrt2ε = sqrt(2 * ε_T)
    h = fd_step !== nothing ? eltype(Xbar)(fd_step) : cbrt(eps(eltype(Xbar)))
    T = size(Xbar, 2)

    # --- Exact forward step (binary accept/reject) ---
    G_X = gradlogp_batch(Xbar)
    Y = Xbar .+ ε_T .* _apply_M_batched(G_X, cholM) .+ sqrt2ε .* _apply_L_batched(Ξ, cholM)
    G_Y = gradlogp_batch(Y)
    Lp_X = logp_batch(Xbar)
    Lp_Y = logp_batch(Y)
    LogQ_YX = logq_mala_batched(Y, Xbar, G_X, ε_T; cholM=cholM)
    LogQ_XY = logq_mala_batched(Xbar, Y, G_Y, ε_T; cholM=cholM)
    Logα = @. (Lp_Y + LogQ_XY) - (Lp_X + LogQ_YX)
    log_U = log.(U)
    accepted = @. log_U < Logα
    FT = ifelse.(reshape(accepted, 1, T), Y, Xbar)

    # --- JVP of sigmoid surrogate via central-difference FD ---
    # f_surr(Xbar + h Z) and f_surr(Xbar - h Z) use the same tape (Ξ, U).
    F_plus = _mala_surrogate_step_batched(
        logp_batch, gradlogp_batch, Xbar .+ h .* Z, ε_T, Ξ, U; cholM=cholM
    )
    F_minus = _mala_surrogate_step_batched(
        logp_batch, gradlogp_batch, Xbar .- h .* Z, ε_T, Ξ, U; cholM=cholM
    )
    Jvp = (F_plus .- F_minus) ./ (2 * h)
    Jt = Z .* Jvp

    return FT, Jt
end

end # module
