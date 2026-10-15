# =============================================================================
# parametric_sweep_tests.jl — the generalized-sweep-lemma gates
# (uncertain_evidence 35ae25c §"The generalized sweep").
#
# b. PARAMETRIC SWEEP EXACTNESS: brute-force oracle over ALL subsets on
#    small heterogeneous instances (Jeffreys + IG priors, with and without the
#    profiled-γ prior table), including integer-grid instances whose crossings
#    COINCIDE — the kinetic walk's re-sort branch — plus property tests
#    (crossing bound, homoscedastic degradation), and a pin against the
#    retired re-sort-per-interval implementation on a fixed seed grid.
# a. FAST-PATH BIT-IDENTITY: equal gains must take the historical
#    single-sort path and reproduce it bit-for-bit.
# c. SCALE-EQUIVARIANCE PIN (the multiplicative-convention motivation):
#    scaling all residuals by c leaves the selected partition invariant and
#    shifts the profiled scale by c. This holds because q_i and the gains
#    are s-free under Ṽ_i = s²·V_i; under the OLD additive reading
#    (Ṽ = s² + leverage frozen at a reference scale) q_i and |Ṽ_i| would be
#    s-dependent, the lemma separation fails, and this pin CANNOT hold —
#    that latent violation is the motivation for the convention change.
# =============================================================================

@testitem "parametric_sweep" begin
    using Test, Random
    using RansacScoringDoneRight
    using RansacScoringDoneRight: default_scoring_workspace, _sweep_score, sweep!,
        _build_lg_table, _alpha0, _build_prior_table
    using VisualGeometryCore: IGPrior, JeffreysPrior

    # Reference (brute-force) score of an explicit support I — the same formula
    # sweep! evaluates, applied to an arbitrary subset.
    function _brute_best(q, pen, n, m, dg, log_two_outlier_halfwidth, prior::IGPrior, prior_table = nothing)
        lg = _build_lg_table(n, dg; alpha0 = prior.alpha0)
        best = -Inf; bestI = Int[]
        for mask in 1:(2^n - 1)                       # exhaustive subset enumeration
            k = count_ones(mask)
            k <= m && continue
            RSS = 0.0; P = 0.0
            for i in 1:n
                if (mask >> (i - 1)) & 1 == 1
                    RSS += q[i]; P += pen[i]
                end
            end
            RSS = max(RSS, eps())
            ν½ = dg * (k - m) / 2
            S = _sweep_score(prior, lg[k - m], ν½, RSS, (n - k) * dg * log_two_outlier_halfwidth) - P / 2
            prior_table !== nothing && (S += prior_table[k])
            if S > best
                best = S
                bestI = [i for i in 1:n if (mask >> (i - 1)) & 1 == 1]
            end
        end
        return best, bestI
    end

    # The score of one explicit support I (the brute force's formula).
    function _subset_score(q, pen, I, n, m, dg, log_two_outlier_halfwidth, prior::IGPrior, prior_table)
        k = length(I)
        lg = _build_lg_table(n, dg; alpha0 = prior.alpha0)
        S = _sweep_score(prior, lg[k - m], dg * (k - m) / 2, max(sum(q[I]), eps()),
                         (n - k) * dg * log_two_outlier_halfwidth) - sum(pen[I]) / 2
        return prior_table === nothing ? S : S + prior_table[k]
    end

    @testset "parametric sweep == brute force (oracle, heterogeneous gains)" begin
        for seed in 1:200
            rng = MersenneTwister(seed)
            n = rand(rng, 5:12)
            m = rand(rng, 1:3)
            dg = rand(rng, 1:2)
            log_two_outlier_halfwidth = log(2 * (0.5 + rand(rng)))
            q = rand(rng, n) .^ 2 .* 10 .+ 1e-6
            # heterogeneous penalties with deliberate CONFLICTED pairs (large gain
            # with large residual): correlate some penalties negatively with q
            pen = 0.5 .* randn(rng, n) .+ (rand(rng, n) .< 0.5) .* (-0.3 .* q)
            prior = seed % 2 == 0 ? JeffreysPrior() : IGPrior(1.3, 0.7)
            sws = default_scoring_workspace(n; dg, scale_prior = prior)
            S, k = sweep!(sws.perm, sws.lg_table, m, log_two_outlier_halfwidth, dg, q, n;
                          scratch = sws.scratch, penalties = pen, scale_prior = prior)
            Sb, Ib = _brute_best(q, pen, n, m, dg, log_two_outlier_halfwidth, prior)
            @test isapprox(S, Sb; rtol = 0, atol = 1e-9)
            @test k == length(Ib)
            @test sort(sws.perm[1:k]) == sort(Ib)      # the materialized support IS the argmax
        end
    end

    @testset "kinetic walk: coincident crossings and the profiled prior == brute force" begin
        # Residuals and penalties on small integer grids make many pairwise
        # crossings μ_ij COINCIDE exactly (and repeat points outright), so groups
        # of several crossings — the walk's re-sort branch — occur alongside lone
        # adjacent swaps. The profiled-γ table enters every prefix score.
        for seed in 1:150
            rng = MersenneTwister(1000 + seed)
            n = rand(rng, 5:12)
            m = rand(rng, 1:3)
            dg = rand(rng, 1:2)
            log_two_outlier_halfwidth = log(2 * (0.5 + rand(rng)))
            q = Float64.(rand(rng, 1:4, n)) .+ (seed % 3 == 0 ? 0.0 : 1e-3 .* rand(rng, n))
            pen = 0.5 .* Float64.(rand(rng, -2:2, n))
            prior = seed % 2 == 0 ? JeffreysPrior() : IGPrior(1.3, 0.7)
            pt = seed % 4 < 2 ? _build_prior_table(n) : nothing
            sws = default_scoring_workspace(n; dg, scale_prior = prior)
            S, k = sweep!(sws.perm, sws.lg_table, m, log_two_outlier_halfwidth, dg, q, n;
                          scratch = sws.scratch, penalties = pen, prior_table = pt,
                          scale_prior = prior)
            Sb, Ib = _brute_best(q, pen, n, m, dg, log_two_outlier_halfwidth, prior, pt)
            @test isapprox(S, Sb; rtol = 0, atol = 1e-9)
            # The materialized support attains the optimum. (Integer grids can tie
            # two subsets exactly, and either is then an argmax, so the support is
            # pinned by its score rather than as a set.)
            @test isapprox(_subset_score(q, pen, sws.perm[1:k], n, m, dg, log_two_outlier_halfwidth, prior, pt), Sb;
                           rtol = 0, atol = 1e-9)
        end
    end

    # The retired implementation (re-sort and re-score every prefix at every
    # interval's representative μ), verbatim — the reference the kinetic walk
    # replaced. The two enumerate the same candidate family; they may differ only
    # in the summation order of carried-forward prefix sums.
    function _retired_parametric_sweep!(perm::Vector{Int}, lg_table::Vector{Float64},
                                model_dof::Int, log_two_outlier_halfwidth::Float64, dg::Int,
                                scores::AbstractVector{T}, penalties::AbstractVector{Float64},
                                prior_table::Union{Nothing,AbstractVector{Float64}},
                                scale_prior::IGPrior, n::Int) where T
        # all positive pairwise crossings (conflicted pairs only)
        cross = Float64[]
        @inbounds for i in 1:(n - 1), j in (i + 1):n
            dq = Float64(scores[i]) - Float64(scores[j])
            dq == 0.0 && continue
            μ = ((penalties[j] - penalties[i]) / 2) / dq     # (g_i - g_j)/(q_i - q_j)
            μ > 0.0 && push!(cross, μ)
        end
        sort!(cross)
        # representative μ per ordering interval: below the first crossing,
        # midpoints of consecutive distinct crossings, above the last
        μs = Float64[]
        if isempty(cross)
            push!(μs, 1.0)
        else
            push!(μs, cross[1] / 2)
            prev = cross[1]
            @inbounds for c in cross
                if c > prev * (1 + 1e-13) + 1e-300
                    push!(μs, (prev + c) / 2)
                    prev = c
                end
            end
            push!(μs, cross[end] * 2 + 1.0)
        end

        m = model_dof
        dg_f = Float64(dg)
        ord = Vector{Int}(undef, n)
        bestord = Vector{Int}(undef, n)
        best_S = -Inf; best_k = 0
        for μ in μs
            # descending t(μ); deterministic ties by (ascending q, index)
            sortperm!(ord, 1:n;
                      by = i -> (-( -penalties[i] / 2 - μ * Float64(scores[i]) ),
                                 Float64(scores[i]), i))
            RSS = 0.0; pens = 0.0   # Float64 accumulation regardless of storage eltype
            @inbounds for k in 1:n
                idx = ord[k]
                RSS += Float64(scores[idx])
                pens += Float64(penalties[idx])
                k <= m && continue
                RSSc = max(RSS, eps(Float64))
                ν½ = dg_f * (k - m) / 2
                S = _sweep_score(scale_prior, lg_table[k - m], ν½, RSSc,
                                 (n - k) * dg_f * log_two_outlier_halfwidth) - pens / 2
                prior_table !== nothing && (S += Float64(prior_table[k]))
                if S > best_S
                    best_S = S; best_k = k
                    copyto!(bestord, ord)
                end
            end
        end
        # perm[1:k*] IS the selected support (ConsensusSet/mask contract)
        if length(perm) == n
            copyto!(perm, bestord)
        else
            @inbounds for k in 1:n; perm[k] = bestord[k]; end
        end
        return best_S, best_k
    end


    @testset "kinetic walk == the retired re-sort-per-interval sweep (seed grid)" begin
        # predictive-scoring-like instances: χ²_dg inliers, wide outliers, penalties
        # log V_i ≥ 0, the m sample points exact (q = 0, penalty 0)
        function instance(rng, n, dg; m = 4)
            q = [rand(rng) < 0.7 ? sum(abs2, randn(rng, dg)) : 400 * rand(rng) for _ in 1:n]
            pen = [log1p(0.05 * randexp(rng) * (1 + 3 * rand(rng))) for _ in 1:n]
            q[1:m] .= 0.0; pen[1:m] .= 0.0
            return q, pen
        end
        m = 4
        for seed in 1:8, n in (20, 60), dg in (1, 2),
            prior in (JeffreysPrior(), IGPrior(1.3, 0.7)), profiled in (false, true)
            rng = MersenneTwister(seed)
            q, pen = instance(rng, n, dg)
            log_two_outlier_halfwidth = log(2 * (5 + 30 * rand(rng)))
            pt = profiled ? _build_prior_table(n) : nothing
            lg = _build_lg_table(n, dg; alpha0 = prior.alpha0)
            perm_new = zeros(Int, n); perm_old = zeros(Int, n)
            S, k = sweep!(perm_new, copy(lg), m, log_two_outlier_halfwidth, dg, q, n;
                          penalties = pen, prior_table = pt, scale_prior = prior)
            So, ko = _retired_parametric_sweep!(perm_old, copy(lg), m, log_two_outlier_halfwidth, dg, q, pen,
                                                pt, prior, n)
            @test k == ko
            @test sort(perm_new[1:k]) == sort(perm_old[1:ko])
            @test S ≈ So rtol = 1e-14
        end
    end

    @testset "properties: crossing bound + homoscedastic degradation" begin
        rng = MersenneTwister(42)
        n = 40; m = 2; dg = 1; log_two_outlier_halfwidth = log(0.4)
        q = rand(rng, n) .* 5
        # homoscedastic degradation: constant penalties reduce to the prefix
        # family of the single q-sort (bit-identical fast path)
        penc = fill(1.234, n)
        sws1 = default_scoring_workspace(n; dg)
        sws2 = default_scoring_workspace(n; dg)
        S1, k1 = sweep!(sws1.perm, sws1.lg_table, m, log_two_outlier_halfwidth, dg, q, n;
                        scratch = sws1.scratch, penalties = penc)
        q2 = copy(q)
        S2, k2 = sweep!(sws2.perm, sws2.lg_table, m, log_two_outlier_halfwidth, dg, q2, n;
                        scratch = sws2.scratch, penalties = penc, sort_key = copy(q))
        @test S1 === S2 && k1 === k2 && sws1.perm == sws2.perm
        # crossing bound: the enumeration terminates within C(n,2) events and its
        # optimum dominates every single-μ prefix family (spot check μ grid)
        pen = randn(rng, n)
        sws = default_scoring_workspace(n; dg)
        S, k = sweep!(sws.perm, sws.lg_table, m, log_two_outlier_halfwidth, dg, q, n;
                      scratch = sws.scratch, penalties = pen)
        lg = _build_lg_table(n, dg)
        for μ in (1e-3, 0.1, 1.0, 10.0, 1e3)
            ordμ = sort(1:n; by = i -> -(-pen[i] / 2 - μ * q[i]))
            RSS = 0.0; pens = 0.0
            for kk in 1:n
                RSS += q[ordμ[kk]]; pens += pen[ordμ[kk]]
                kk <= m && continue
                ν½ = dg * (kk - m) / 2
                Sμ = _sweep_score(IGPrior(), lg[kk - m], ν½, max(RSS, eps()),
                                  (n - kk) * dg * log_two_outlier_halfwidth) - pens / 2
                @test S >= Sμ - 1e-9
            end
        end
    end

    @testset "scale-equivariance pin (multiplicative convention)" begin
        rng = MersenneTwister(7)
        n = 30; m = 3; dg = 1; log_two_outlier_halfwidth = log(1.7)
        q = rand(rng, n) .* 3 .+ 1e-4          # s-free unit-scale q_i = r_i' V_i^{-1} r_i
        pen = randn(rng, n) .* 0.7             # s-free log|V_i|
        for c in (0.25, 1.0, 8.0)
            # the scale-family statement: residuals scale by c AND the raw-domain
            # floor half-width co-scales (by c) — then the total score shifts
            # by the k-independent constant −(nd − n_θ)·log c and the argmax is
            # invariant. (With a FIXED floor the −ν_k·log c tilt legitimately
            # moves the boundary — that is a different experiment, not this pin.)
            sws = default_scoring_workspace(n; dg)
            S, k = sweep!(sws.perm, sws.lg_table, m, log_two_outlier_halfwidth + log(c), dg, c^2 .* q, n;
                          scratch = sws.scratch, penalties = pen)
            sws0 = default_scoring_workspace(n; dg)
            S0, k0 = sweep!(sws0.perm, sws0.lg_table, m, log_two_outlier_halfwidth, dg, q, n;
                            scratch = sws0.scratch, penalties = pen)
            @test k == k0                                   # selected partition invariant
            @test sort(sws.perm[1:k]) == sort(sws0.perm[1:k0])
            # profiled scale shifts by exactly c: ŝ² = Q_I/ν_k scales by c²
            ν = dg * (k - m)
            @test sqrt(sum(c^2 .* q[sws.perm[1:k]]) / ν) ≈ c * sqrt(sum(q[sws0.perm[1:k0]]) / ν) rtol = 1e-12
        end
    end

    @testset "the log Γ table: lg[k] = log Γ(k·d_g/2 + α₀)" begin
        lg = _build_lg_table(100, 1)
        @test length(lg) == 100
        @test lg[1] ≈ 0.5 * log(π) atol = 1.0e-12   # log Γ(1/2)
        @test lg[2] ≈ 0.0 atol = 1.0e-12             # log Γ(1)
        @test lg[4] ≈ 0.0 atol = 1.0e-12             # log Γ(2)
        @test lg[6] ≈ log(2.0) atol = 1.0e-12        # log Γ(3)
        @test _build_lg_table(3, 2)[3] ≈ log(2.0) atol = 1.0e-12             # d_g = 2: log Γ(3)
        @test _build_lg_table(2, 1; alpha0 = 1.0)[2] ≈ 0.0 atol = 1.0e-12    # log Γ(1 + 1)
    end
end
