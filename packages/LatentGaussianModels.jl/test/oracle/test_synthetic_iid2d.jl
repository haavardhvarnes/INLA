# Oracle test: bivariate IID random effects (`IID2D`) on synthetic data
# vs R-INLA's `2diid`. Smallest oracle for the `IIDND_Sep{2}` component
# introduced in Phase I-A PR-1a (ADR-022).
#
# Fixture: scripts/generate-fixtures/lgm/synthetic_iid2d.R.
# Skipped transparently if the JLD2 fixture has not been generated.
#
# Layout note: R-INLA's `2diid` lays out the latent vector as
# `(b_1[1], b_2[1], b_1[2], b_2[2], …)` (INTERLEAVED by group), while
# our `IIDND_Sep{2}` uses `(b_1[1..n], b_2[1..n])` (CONTIGUOUS by
# dimension). The two conventions yield the same hyperparameter and
# fixed-effect posteriors — only the random-effect slot ordering
# differs. The R script feeds the data in interleaved order on its
# side; the Julia test feeds the data in contiguous order on its side.

include("load_fixture.jl")

using Test
using SparseArrays
using LatentGaussianModels: GaussianLikelihood, Intercept, IID2D,
                            LinearProjector, LatentGaussianModel,
                            inla, fixed_effects, hyperparameters,
                            log_marginal_likelihood

const IID2D_FIXTURE = "synthetic_iid2d"

# Tolerances. n_groups = 30, m_reps = 5 → 300 observations is enough for
# tight posteriors on (β_1, β_2, τ_y, τ_1, τ_2) but ρ has a wider
# posterior (sd ≈ 0.15 in R-INLA) so the absolute tolerance on ρ is
# loose. Comparison is mode (Julia θ̂) vs mean (R-INLA summary) which
# differ systematically for asymmetric log-precision posteriors —
# precisions get a 15% relative band, the correlation gets 0.10
# absolute (≈ ½ R-INLA posterior sd).
#
# Phase F.5 mlik resolution (2026-05-03): the original PR-1a `isfinite`
# assertion documented an ~8 nat gap and conjectured a `2diid`-specific
# R-INLA normalising-constant adjustment. That conjecture was wrong.
# Root cause: R's `y ~ -1 + intercept_1 + intercept_2 + f(idx, "2diid", …)`
# treats `intercept_d` as ordinary fixed effects with R-INLA's default
# `control.fixed$prec = 0.001` (proper Gaussian prior), NOT as
# auto-intercepts under `prec.intercept = 0`. The Julia model was
# instantiated with two `Intercept()` (improper, default) — the
# convention mismatch contributes exactly `-½·log(prec)` per intercept
# (verified empirically: per-intercept gap is 3.454 ≈ ½·log(1000)
# constant across k = 1, 2, 3 intercepts on a no-random-effect
# controlled experiment). Switching the Julia oracle to two
# `Intercept(prec = 1e-3, improper = false)` slots — matching R's
# convention — drops the residual gap to ~1.5 nats (1.8%).
const IID2D_FE_TOL = 0.05
const IID2D_TAU_REL_TOL = 0.15
const IID2D_RHO_ABS_TOL = 0.10
const IID2D_MLIK_REL_TOL = 0.05

_rel_iid2d(a, b) = abs(a - b) / max(abs(b), 1.0)

function _row_iid2d(frame, name::AbstractString, col::AbstractString)
    rn_raw = frame["rownames"]
    rn = rn_raw isa AbstractString ? [String(rn_raw)] : String.(rn_raw)
    idx = findfirst(==(name), rn)
    idx === nothing && error("row '$name' not found (have: $(join(rn, "; ")))")
    col_raw = frame[col]
    return col_raw isa Real ? Float64(col_raw) : Float64(col_raw[idx])
end

@testset "synthetic_iid2d vs R-INLA" begin
    if !has_oracle_fixture(IID2D_FIXTURE)
        @test_skip "oracle fixture $IID2D_FIXTURE not generated (see scripts/generate-fixtures/)"
    else
        fx = load_oracle_fixture(IID2D_FIXTURE)
        @test fx["name"] == IID2D_FIXTURE
        @test haskey(fx, "summary_fixed")
        @test haskey(fx, "summary_hyperpar")

        if !haskey(fx, "input")
            @test_skip "fixture has no `input` field — regenerate with the current R script"
        else
            inp = fx["input"]
            y_1 = Float64.(inp["y_1"])
            y_2 = Float64.(inp["y_2"])
            n_groups = Int(inp["n_groups"])
            m_reps   = Int(inp["m_reps"])
            @test length(y_1) == n_groups * m_reps
            @test length(y_2) == n_groups * m_reps

            n = n_groups
            N_per_dim = n * m_reps
            N_obs = 2 * N_per_dim

            # Latent layout: x = [β_1, β_2, b_1[1..n], b_2[1..n]].
            # Length = 2 + 2n. Build the (2 N_per_dim) × (2 + 2n) projector A.
            n_lat = 2 + 2n
            Is = Int[]; Js = Int[]; Vs = Float64[]
            sizehint!(Is, 4 * N_per_dim)
            sizehint!(Js, 4 * N_per_dim)
            sizehint!(Vs, 4 * N_per_dim)
            # Dim-1 rows: y_1, picks (β_1, b_1[group_i]).
            for k in 1:N_per_dim
                grp = (k - 1) ÷ m_reps + 1
                push!(Is, k); push!(Js, 1);          push!(Vs, 1.0)  # β_1
                push!(Is, k); push!(Js, 2 + grp);    push!(Vs, 1.0)  # b_1[grp]
            end
            # Dim-2 rows: y_2, picks (β_2, b_2[group_i]).
            for k in 1:N_per_dim
                grp = (k - 1) ÷ m_reps + 1
                row = N_per_dim + k
                push!(Is, row); push!(Js, 2);            push!(Vs, 1.0) # β_2
                push!(Is, row); push!(Js, 2 + n + grp);  push!(Vs, 1.0) # b_2[grp]
            end
            A = sparse(Is, Js, Vs, N_obs, n_lat)
            mapping = LinearProjector(A)

            ℓ = GaussianLikelihood()
            # Two proper `Intercept(prec=1e-3, improper=false)` slots match
            # R's `y ~ -1 + intercept_1 + intercept_2 + …` convention: with
            # `-1`, R-INLA does NOT auto-insert an improper intercept; the
            # `intercept_d` columns are ordinary fixed effects under the
            # default `control.fixed$prec = 0.001`. See header comment for
            # the Phase F.5 excavation that pinned this convention.
            model = LatentGaussianModel(
                ℓ,
                (Intercept(prec=1.0e-3, improper=false),
                 Intercept(prec=1.0e-3, improper=false),
                 IID2D(n)),
                mapping)

            y = vcat(y_1, y_2)
            # dim(θ) = 4 (τ_y + τ_1 + τ_2 + ρ) → CCD via :auto.
            res = inla(model, y; int_strategy = :auto)

            # --- Fixed effects ------------------------------------------------
            sf = fx["summary_fixed"]
            β_1_R = _row_iid2d(sf, "intercept_1", "mean")
            β_2_R = _row_iid2d(sf, "intercept_2", "mean")
            fe = fixed_effects(model, res)
            @test length(fe) == 2
            @test _rel_iid2d(fe[1].mean, β_1_R) < IID2D_FE_TOL
            @test _rel_iid2d(fe[2].mean, β_2_R) < IID2D_FE_TOL

            # --- Hyperparameters ----------------------------------------------
            sh = fx["summary_hyperpar"]
            τ_y_R = _row_iid2d(sh, "Precision for the Gaussian observations", "mean")
            τ_1_R = _row_iid2d(sh, "Precision for idx (first component)",  "mean")
            τ_2_R = _row_iid2d(sh, "Precision for idx (second component)", "mean")
            ρ_R   = _row_iid2d(sh, "Rho for idx", "mean")

            # θ̂ ordering: likelihood hyperparams first, then component
            # hyperparams in component order. Intercepts are
            # hyperparameter-free, so:
            #   θ̂[1] = log τ_y  (Gaussian likelihood)
            #   θ̂[2] = log τ_1  (IID2D first precision)
            #   θ̂[3] = log τ_2  (IID2D second precision)
            #   θ̂[4] = atanh ρ  (IID2D correlation)
            τ_y_J = exp(res.θ̂[1])
            τ_1_J = exp(res.θ̂[2])
            τ_2_J = exp(res.θ̂[3])
            ρ_J   = tanh(res.θ̂[4])

            @test _rel_iid2d(τ_y_J, τ_y_R) < IID2D_TAU_REL_TOL
            @test _rel_iid2d(τ_1_J, τ_1_R) < IID2D_TAU_REL_TOL
            @test _rel_iid2d(τ_2_J, τ_2_R) < IID2D_TAU_REL_TOL
            @test abs(ρ_J - ρ_R) < IID2D_RHO_ABS_TOL

            hp = hyperparameters(model, res)
            @test length(hp) == 4

            # --- Marginal log-likelihood --------------------------------------
            # R-INLA's `mlik` has two entries: [Integration estimate, Gaussian
            # estimate]. Compare against the Integration estimate, mirroring
            # the BYM2 / Joint-Gauss-Pois oracles.
            mlik_J = log_marginal_likelihood(res)
            mlik_R = Float64(fx["mlik"][1])
            @test _rel_iid2d(mlik_J, mlik_R) < IID2D_MLIK_REL_TOL
        end
    end
end
