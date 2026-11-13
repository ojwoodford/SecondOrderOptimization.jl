using Test, Random, LinearAlgebra, SparseArrays, StaticArrays, Static
using SecondOrderOptimization, BlockLinearSystems

# Tests for the BlockLinearSystems extension (ext/BlockLinearSystemsExt.jl): Schur-complement linear systems.
# Every Schur solve is compared against a dense Cholesky solve of the full damped system.

const SOOExt = Base.get_extension(SecondOrderOptimization, :BlockLinearSystemsExt)

"""
    SchurTestProblem

A random, strictly diagonally dominant (hence positive definite) bipartite system with retained
variables first and eliminated variables second, in full dense form plus everything needed to build
`SchurBlockMatrix` objects from it.
"""
struct SchurTestProblem
    H::Matrix{Float64}
    b::Vector{Float64}
    r_dims::Vector{Int}
    e_dims::Vector{Int}
    couplings::Vector{Vector{Int}}
    rr_pairs::Vector{Tuple{Int, Int}}   # retained-retained block couplings (r > r), beyond the diagonal
end

function SchurTestProblem(rng, r_dims, e_dims, couplings; rr_pairs=Tuple{Int, Int}[])
    nr, ne = sum(r_dims), sum(e_dims)
    n = nr + ne
    roff = cumsum([1; r_dims[1:end-1]])
    eoff = nr .+ cumsum([1; e_dims[1:end-1]])
    H = zeros(n, n)
    function fillblock!(r0, nrow, c0, ncol)
        H[r0:r0+nrow-1, c0:c0+ncol-1] .= 2 .* rand(rng, nrow, ncol) .- 1
    end
    for (r, d) in enumerate(r_dims)
        fillblock!(roff[r], d, roff[r], d)
    end
    for (e, d) in enumerate(e_dims)
        fillblock!(eoff[e], d, eoff[e], d)
    end
    for (e, coupled) in enumerate(couplings), r in coupled
        fillblock!(roff[r], r_dims[r], eoff[e], e_dims[e])
    end
    for (r1, r2) in rr_pairs
        fillblock!(roff[r1], r_dims[r1], roff[r2], r_dims[r2])
    end
    # Symmetrize from the upper triangle (block diagonals are symmetrized element-wise)
    H = Matrix(Symmetric(H, :U))
    # Make strictly diagonally dominant, but keep the conditioning moderate
    for i in 1:n
        H[i, i] = sum(abs, view(H, i, :)) - abs(H[i, i]) + 0.5 + rand(rng)
    end
    return SchurTestProblem(H, randn(rng, n), r_dims, e_dims, couplings, rr_pairs)
end

nr(p::SchurTestProblem) = sum(p.r_dims)

function schur_structure(p::SchurTestProblem; nchunks=1)
    return SchurStructure(p.r_dims, p.e_dims, p.couplings; nchunks)
end

function fill_ce!(p::SchurTestProblem, structure::SchurStructure, E_data, C_data)
    nr_ = nr(p)
    for e in eachindex(p.e_dims)
        de = p.e_dims[e]
        eo = structure.eoffsets[e]
        eoff = nr_ + structure.boffsets_e[e]
        E_data[eo:eo+de^2-1] .= vec(p.H[eoff:eoff+de-1, eoff:eoff+de-1])
        for c in structure.eliminated_ptr[e]:structure.eliminated_ptr[e+1]-1
            r = structure.entry_retained[c]
            dr = p.r_dims[r]
            ro = structure.boffsets_r[r]
            co = structure.coffsets[c]
            # Stored as de x dr column-major: C_data[co + (r-1)*de + i-1] = H[c_r, p_i]
            C_data[co:co+dr*de-1] .= vec(p.H[ro:ro+dr-1, eoff:eoff+de-1]')
        end
    end
    return nothing
end

function dense_schur_matrix(p::SchurTestProblem; nchunks=1)
    structure = schur_structure(p; nchunks)
    n_r = nr(p)
    R = p.H[1:n_r, 1:n_r]
    E_data = zeros(sum(abs2, p.e_dims))
    C_data = zeros(structure.coffsets[end] + Int(structure.r_dims[structure.entry_retained[end]]) * Int(structure.e_dims[end]) - 1)
    fill_ce!(p, structure, E_data, C_data)
    return SchurBlockMatrix(structure, R, E_data, C_data)
end

function sparse_schur_matrix(p::SchurTestProblem; nchunks=1)
    structure = schur_structure(p; nchunks)
    pattern = build_schur_pattern(structure)
    coords = Tuple{Int, Int}[]
    cb = pattern.block_colptr
    for r2 in 1:structure.nrblocks, k in cb[r2]:cb[r2+1]-1
        r1 = pattern.block_rowval[k]       # r1 <= r2 in the upper-triangle pattern
        push!(coords, (r2, r1))            # store lower-triangle block (row = r2, col = r1)
    end
    append!(coords, p.rr_pairs)
    unique!(coords)
    R = SparseBlockLinearSystem{Float64}(coords, p.r_dims)
    roff = structure.boffsets_r
    for (r1, r2) in coords
        block(R, r1, r2) .= p.H[roff[r1]:roff[r1]+p.r_dims[r1]-1, roff[r2]:roff[r2]+p.r_dims[r2]-1]
    end
    E_data = zeros(sum(abs2, p.e_dims))
    C_data = zeros(structure.coffsets[end] + Int(structure.r_dims[structure.entry_retained[end]]) * Int(structure.e_dims[end]) - 1)
    fill_ce!(p, structure, E_data, C_data)
    return SchurBlockMatrix(structure, R, E_data, C_data)
end

function make_schur_ls(kind::Symbol, p::SchurTestProblem, scaling=ones(length(p.b)); nchunks=1)
    n = length(p.b)
    if kind === :dense
        return SOOExt.DenseSchurLinearSystem(dense_schur_matrix(p; nchunks), copy(p.b), zeros(n), copy(scaling))
    else
        return SOOExt.SparseSchurLinearSystem(sparse_schur_matrix(p; nchunks), copy(p.b), zeros(n), copy(scaling))
    end
end

"Reference solution: dense Cholesky of the full system with `lambda * diag(damping)` added to the diagonal."
function reference_solve(p::SchurTestProblem, lambda, damping)
    Hd = p.H + lambda * Diagonal(damping)
    return cholesky(Symmetric(Hd)) \ p.b
end

function standard_problem(seed=1; rr_pairs=Tuple{Int, Int}[])
    rng = Random.Xoshiro(seed)
    r_dims = [6, 6, 6, 6]
    e_dims = [3, 3, 3, 3, 3, 3, 3, 2, 2, 2, 2, 2, 1, 1, 1, 1, 1, 1, 1, 1]
    # Retained blocks 1-2 and 3-4 are coupled to eliminated blocks together; 2-3 are linked through a few eliminated blocks
    couplings = [
        [1, 2], [1, 2], [1, 2, 3], [2, 3], [3, 4], [3, 4], [1, 4],
        [1, 2], [2, 3], [3, 4], [1, 2, 3, 4], [4],
        [1], [2], [3], [4], [1, 2], [3, 4], [2, 3], [1, 4],
    ]
    return SchurTestProblem(rng, r_dims, e_dims, couplings; rr_pairs)
end

@testset "BlockLinearSystemsExt: Schur solve equals full Cholesky solve" begin
    p = standard_problem()
    n = length(p.b)
    scalings = (
        "I" => ones(n),
        # Marquardt (:levenbergmarquardt_dtd) scaling: |diag(H)|, damping is lambda * diag(H), not squared (B2)
        "D'D" => abs.(diag(p.H)),
        "wide-range" => exp.(range(-4, 8; length=n)),
    )
    for kind in (:dense, :sparse), solver in (:auto, :ldl), (sname, scaling) in scalings, lambda in (0.0, 0.3)
        @testset "$kind, $solver, $sname, lambda=$lambda" begin
            ls = make_schur_ls(kind, p, scaling)
            SecondOrderOptimization.dampen!(ls, lambda, scaling)
            @test SecondOrderOptimization.solve!(ls, solver) == SecondOrderOptimization.Success
            x_ref = reference_solve(p, lambda, scaling)
            @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
        end
    end
end

# Copy the numerical content of `src` (a SchurBlockMatrix) into `dst`
function copy_content!(dst::SchurBlockMatrix, src::SchurBlockMatrix)
    dst.R isa Matrix ? copyto!(dst.R, src.R) : copyto!(dst.R.data, src.R.data)
    copyto!(dst.E_data, src.E_data)
    copyto!(dst.C_data, src.C_data)
    return dst
end

@testset "BlockLinearSystemsExt: copy_structure gives an independent trial system (B1)" begin
    p1 = standard_problem(1)
    p2 = standard_problem(2)
    n = length(p1.b)
    for kind in (:dense, :sparse)
        @testset "$kind" begin
            ls = make_schur_ls(kind, p1)
            trial = SecondOrderOptimization.copy_structure(ls)

            # New storage for the Hessian and gradient, shared x
            @test trial.H !== ls.H
            @test trial.H.R !== ls.H.R
            @test trial.H.E_data !== ls.H.E_data
            @test trial.H.C_data !== ls.H.C_data
            @test trial.b !== ls.b
            @test trial.x === ls.x
            @test SecondOrderOptimization.getA(trial) === trial.H

            # Linearize the trial at a different point: this must not touch the current system
            SecondOrderOptimization.zero!(trial)
            copy_content!(trial.H, make_schur_ls(kind, p2).H)
            trial.b .= p2.b
            # Reject the trial; retry on the current system with different damping, twice
            for lambda in (0.1, 2.0)
                SecondOrderOptimization.dampen!(ls, lambda)
                @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
                x_ref = reference_solve(p1, lambda, ones(n))
                @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
            end

            # And the trial system solves its own problem, writing into the shared x
            SecondOrderOptimization.dampen!(trial, 0.1)
            @test SecondOrderOptimization.solve!(trial) == SecondOrderOptimization.Success
            x_ref2 = reference_solve(p2, 0.1, ones(n))
            @test norm(trial.x - x_ref2) <= 1e-10 * norm(x_ref2)
        end
    end
end

# Two groups of retained blocks ({1, 2} and {3, 4}) that share no eliminated block with each other, coupled only by
# direct retained-retained blocks (odometry / loop-closure style), which have no eliminated variable.
function coupled_groups_problem(seed=3)
    rng = Random.Xoshiro(seed)
    r_dims = [6, 6, 6, 6]
    e_dims = [3, 3, 3, 3, 2, 2, 1, 1]
    couplings = [[1, 2], [1, 2], [3, 4], [3, 4], [1], [4], [2, 1], [3, 4]]
    return SchurTestProblem(rng, r_dims, e_dims, couplings; rr_pairs=[(3, 1), (4, 2), (2, 1)])
end

@testset "BlockLinearSystemsExt: retained-retained couplings without a shared eliminated variable (B4)" begin
    p = coupled_groups_problem()
    n = length(p.b)
    structure = schur_structure(p)

    # Pattern: the extra pairs get slots, in either order, and nothing else changes
    plain = build_schur_pattern(structure)
    withextra = build_schur_pattern(structure; extra_blocks=[(3, 1), (2, 4)])
    @test !plain.block_pattern[1, 3] && !plain.block_pattern[2, 4]
    @test withextra.block_pattern[1, 3] && withextra.block_pattern[2, 4]
    @test nnz(withextra.block_pattern) == nnz(plain.block_pattern) + 2
    @test_throws ArgumentError build_schur_pattern(structure; extra_blocks=[(1, 5)])

    # The sparse system fails to build a slot for R's coupling without the extra pairs ...
    H = sparse_schur_matrix(p)
    @test Set(retained_block_pairs(H.R)) ⊇ Set([(3, 1), (4, 2)])
    @test_throws AssertionError build_r_to_s_map(H.R, plain.S_sparse, structure.boffsets_r)
    # ... and builds one with them
    pattern = build_schur_pattern(structure; extra_blocks=retained_block_pairs(H.R))
    b_to_s = build_r_to_s_map(H.R, pattern.S_sparse, structure.boffsets_r)
    # every upper-triangle entry of the diagonal blocks (21 each) and all 36 entries of each off-diagonal block
    @test count(>(0), b_to_s) == 4 * 21 + 36 * length(retained_block_pairs(H.R))

    for kind in (:dense, :sparse), lambda in (0.0, 0.5)
        @testset "$kind, lambda=$lambda" begin
            ls = make_schur_ls(kind, p)
            SecondOrderOptimization.dampen!(ls, lambda)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
            x_ref = reference_solve(p, lambda, ones(n))
            @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
        end
    end
end

@testset "build_schur_pattern scales to many couplings (B8) and can be reused" begin
    # Many retained blocks, each eliminated block coupled to a window of consecutive retained blocks
    nret, nelim = 3000, 6000
    coupled = [collect(r:min(r + 3, nret)) for r in (min.(1 .+ (0:nelim-1) .* nret .÷ nelim, nret))]
    structure = SchurStructure(fill(6, nret), fill(3, nelim), coupled)
    build_schur_pattern(structure)   # compile
    t = @elapsed pattern = build_schur_pattern(structure)
    @test t < 5
    @test nnz(pattern.block_pattern) == length(pattern.block_rowval)
    # Upper triangle with the diagonal; the sliding window gives bandwidth 3
    @test all(pattern.block_rowval[k] <= r for r in 1:nret for k in pattern.block_colptr[r]:pattern.block_colptr[r+1]-1)
    @test nnz(pattern.block_pattern) <= nret * 4

    # Passing a precomputed pattern to the constructor gives the same system
    p = coupled_groups_problem()
    H = sparse_schur_matrix(p)
    pre = build_schur_pattern(H.structure; extra_blocks=retained_block_pairs(H.R))
    ls1 = SOOExt.SparseSchurLinearSystem(H, copy(p.b), zeros(length(p.b)))
    ls2 = SOOExt.SparseSchurLinearSystem(H, copy(p.b), zeros(length(p.b)); pattern=pre)
    @test ls1.S == ls2.S && ls1.r_to_s_map == ls2.r_to_s_map
end

@testset "BlockLinearSystemsExt: undamped solves use Cholesky, fall back on failure (B5)" begin
    p = standard_problem()
    n = length(p.b)
    x_ref = reference_solve(p, 0.0, ones(n))
    for kind in (:dense, :sparse)
        @testset "$kind positive definite" begin
            ls = make_schur_ls(kind, p)
            SecondOrderOptimization.dampen!(ls, 0.0)
            # Solving twice gives identical results (S is rebuilt each time even though Cholesky works in place)
            for _ in 1:2
                @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
                @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
            end
        end
        @testset "$kind indefinite" begin
            # Make the retained diagonal very negative so that S is indefinite, and Cholesky must fail
            q = standard_problem()
            q.H[1, 1] = -50.0
            for solver in (:auto, :ldl)
                ls = make_schur_ls(kind, q)
                SecondOrderOptimization.dampen!(ls, 0.0)
                @test SecondOrderOptimization.solve!(ls, solver) == SecondOrderOptimization.Indefinite
            end
            # With enough damping it is positive definite again, and the fallback is not needed
            ls = make_schur_ls(kind, q)
            SecondOrderOptimization.dampen!(ls, 100.0)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
            x_ref_q = reference_solve(q, 100.0, ones(n))
            @test norm(ls.x - x_ref_q) <= 1e-10 * norm(x_ref_q)
        end
    end
end

@testset "quadratic_model_change uses the undamped model on the full system (B10)" begin
    p = standard_problem()
    n = length(p.b)
    dx = randn(Random.Xoshiro(6), n)
    expected = 0.5 * dot(dx, p.H * dx) + dot(p.b, dx)
    for kind in (:dense, :sparse), lambda in (0.0, 0.7)
        ls = make_schur_ls(kind, p, abs.(diag(p.H)))
        SecondOrderOptimization.dampen!(ls, lambda, abs.(diag(p.H)))
        @test SecondOrderOptimization.quadratic_model_change(ls, dx) ≈ expected rtol = 1e-12
    end
end

@testset "Schur solve is serial and allocation free for small problems; threading matches (B11)" begin
    p = standard_problem()
    n = length(p.b)
    x_ref = reference_solve(p, 0.4, ones(n))
    for kind in (:dense, :sparse)
        ls = make_schur_ls(kind, p; nchunks=1)
        SecondOrderOptimization.dampen!(ls, 0.4)
        SecondOrderOptimization.solve!(ls)
        @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
        H = ls.H
        ws = ls.workspace
        # The reduction and back-substitution kernels allocate nothing when serial
        if kind === :dense
            run_reduce() = reduce_schur_dense!(ls.S, ls.g_S, ls.b_r, ls.b_e, ls.scaling_e, ls.lambda, H.structure, H.E_data, H.C_data, ws)
            @test run_reduce()
            @test (@allocated run_reduce()) == 0
        else
            run_reduce_s() = reduce_schur_sparse!(ls.S, ls.g_S, ls.b_r, ls.b_e, ls.scaling_e, ls.lambda, H.structure, H.E_data, H.C_data,
                ls.block_colptr, ls.block_rowval, ls.block_row_offsets, ls.col_heights, ws)
            @test run_reduce_s()
            @test (@allocated run_reduce_s()) == 0
        end
        run_back() = backsubstitute!(ls.x_e, ls.x_r, H.structure, H.C_data, ws.E_inv_data, ws.z_data)
        run_back()
        @test (@allocated run_back()) == 0
    end

    # Force the threaded code paths (they only engage with more than one thread) and compare
    old = BlockLinearSystems.SCHUR_THREAD_MIN_WORK[]
    try
        BlockLinearSystems.SCHUR_THREAD_MIN_WORK[] = 0
        for kind in (:dense, :sparse), nchunks in (1, 3)
            ls = make_schur_ls(kind, p; nchunks)
            SecondOrderOptimization.dampen!(ls, 0.4)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
            @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
        end
    finally
        BlockLinearSystems.SCHUR_THREAD_MIN_WORK[] = old
    end
end

@testset "BlockLinearSystemsExt: the type of H selects elimination; linsolver names the reduced solver (A2)" begin
    p = standard_problem()
    Hd, Hs = dense_schur_matrix(p), sparse_schur_matrix(p)
    mk(H, s) = SecondOrderOptimization.makelinearsystem(nothing, H, s)
    # The storage of R picks the dense or sparse system, whatever the reduced-system solver
    for s in (:auto, :cholesky, :ldl, static(:auto), static(:ldl), SecondOrderOptimization.auto_solver,
              SecondOrderOptimization.cholesky_solver, SecondOrderOptimization.ldl_solver)
        @test mk(Hd, s) isa SOOExt.DenseSchurLinearSystem
        @test mk(Hs, s) isa SOOExt.SparseSchurLinearSystem
    end
    # Solvers not implemented for the reduced system are rejected when it is built (not treated as :auto)
    sq(x) = sum(abs2, x)
    sq_fdf!(g, H, x) = sq(x)
    for H in (Hd, Hs)
        for s in (:qr, :pardiso, :cg, :minres, :krylov, static(:qr), SecondOrderOptimization.qr_solver)
            err = try mk(H, s); nothing catch e; e end
            @test err isa ArgumentError
            @test occursin("reduced system", sprint(showerror, err))
        end
        opts_qr = OptimizationOptions(linsolver=:qr)
        @test_throws ArgumentError optimize(zeros(length(p.b)), HessianObjective(sq, sq_fdf!; H), opts_qr)
        @test_throws ArgumentError OptimizationWorkspace(zeros(length(p.b)), HessianObjective(sq, sq_fdf!; H), opts_qr)
    end
    # ...and by solve! on a system built directly
    for kind in (:dense, :sparse)
        @test_throws ArgumentError SecondOrderOptimization.solve!(make_schur_ls(kind, p), :qr)
    end
    # The old symbols are unknown even with the extension loaded; other Hessians need no check
    for s in (:schur, :dense_schur, :sparse_schur)
        @test !SecondOrderOptimization.validatelinsolver(s)
        @test_throws ArgumentError OptimizationOptions(linsolver=s)
    end
    @test_throws MethodError OptimizationOptions(reduction=:eliminate)
    for H_other in (nothing, zeros(3, 3), sparse(1.0I, 3, 3))
        x, res = optimize(ones(3), HessianObjective(sq, (g, H, x) -> (g .= 2 .* x; H[diagind(H)] .= 2; sq(x)); H = H_other))
        @test isconverged(res) && norm(x) < 1e-8
    end

    # solve! accepts Symbols, static symbols and the OptimizationLinearSolver enum without ambiguity
    n = length(p.b)
    x_ref = reference_solve(p, 0.3, ones(n))
    for kind in (:dense, :sparse), s in (:auto, :cholesky, :ldl, static(:auto), static(:ldl),
                                        SecondOrderOptimization.auto_solver, SecondOrderOptimization.cholesky_solver, SecondOrderOptimization.ldl_solver)
        ls = make_schur_ls(kind, p)
        SecondOrderOptimization.dampen!(ls, 0.3)
        @test SecondOrderOptimization.solve!(ls, s) == SecondOrderOptimization.Success
        @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
    end
end

@testset "Chunks write disjoint column ranges of one S: no per-chunk copies (M3)" begin
    p = standard_problem()
    n = length(p.b)
    x_ref = reference_solve(p, 0.4, ones(n))
    for kind in (:dense, :sparse), nchunks in (1, 2, 4, 9)
        ls = make_schur_ls(kind, p; nchunks)
        ws = ls.workspace
        @test !hasproperty(ws, :thread_dense_S) && !hasproperty(ws, :thread_nzvals)
        # col_chunks tile the retained blocks without overlap
        @test length(ws.col_chunks) == nchunks
        @test reduce(vcat, collect.(ws.col_chunks)) == collect(1:ls.H.structure.nrblocks)
        SecondOrderOptimization.dampen!(ls, 0.4)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success   # workspace reuse
        @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
    end
    # Forced-threaded run with many chunks gives the same answer
    old = BlockLinearSystems.SCHUR_THREAD_MIN_WORK[]
    try
        BlockLinearSystems.SCHUR_THREAD_MIN_WORK[] = 0
        for kind in (:dense, :sparse)
            ls = make_schur_ls(kind, p; nchunks=3)
            SecondOrderOptimization.dampen!(ls, 0.4)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
            @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
        end
    finally
        BlockLinearSystems.SCHUR_THREAD_MIN_WORK[] = old
    end
end

function to_float32(H::SchurBlockMatrix)
    R = if H.R isa Matrix
        Float32.(H.R)
    else
        S = H.R
        SparseBlockLinearSystem{Float32}(Float32.(S.data), S.indices, S.indicestransposed, S.rowblocksizes, S.columnblocksizes, S.m, S.n)
    end
    return SchurBlockMatrix(H.structure, R, Float32.(H.E_data), Float32.(H.C_data))
end

@testset "Schur solve in Float32 (M4)" begin
    p = standard_problem()
    n = length(p.b)
    x_ref = reference_solve(p, 0.3, ones(n))
    for kind in (:dense, :sparse)
        H = to_float32(kind === :dense ? dense_schur_matrix(p) : sparse_schur_matrix(p))
        ls = kind === :dense ? SOOExt.DenseSchurLinearSystem(H, Float32.(p.b), zeros(Float32, n)) :
                               SOOExt.SparseSchurLinearSystem(H, Float32.(p.b), zeros(Float32, n))
        @test eltype(ls.S) == Float32
        @test eltype(ls.x) == Float32
        SecondOrderOptimization.dampen!(ls, 0.3)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        @test norm(Float64.(ls.x) - x_ref) <= 1e-3 * norm(x_ref)
    end
    # The sparse system's factor type is concrete
    ls = SOOExt.SparseSchurLinearSystem(sparse_schur_matrix(p), copy(p.b), zeros(n))
    @test isconcretetype(typeof(ls.S_factor))
    @test isconcretetype(fieldtype(typeof(ls), :S_factor))

    # Singularity tolerance scales with the precision: a block that is singular to Float32 precision is rejected
    H2 = SMatrix{2, 2, Float32, 4}(1, 1, 1, 1 + 1f-6)
    @test !inv_sym_block(H2, 0f0, SVector{2, Float32}(1, 1)).success
    H2d = SMatrix{2, 2, Float64, 4}(1, 1, 1, 1 + 1e-6)
    @test inv_sym_block(H2d, 0.0, SVector{2, Float64}(1, 1)).success
end

# Eliminated blocks of every size class: tiny closed forms (1-3), the generic static tier (4..D_STATIC)
# and the dynamic tier above D_STATIC
function mixed_dims_problem(seed=11)
    rng = Random.Xoshiro(seed)
    r_dims = [6, 3, 9, 6]
    e_dims = [12, 12, 9, 9, 8, 8, 5, 5, 4, 4, 3, 3, 2, 2, 1, 1]
    coupled = 1:4
    couplings = [sort(unique([rand(rng, coupled) for _ in 1:3])) for _ in e_dims]
    return SchurTestProblem(rng, r_dims, e_dims, couplings)
end


@testset "Eliminated blocks of any size (M5)" begin
    @test BlockLinearSystems.D_STATIC < 12
    p = mixed_dims_problem()
    n = length(p.b)
    scalings = ("I" => ones(n), "D'D" => abs.(diag(p.H)))
    for kind in (:dense, :sparse), nchunks in (1, 3), (sname, scaling) in scalings, lambda in (0.0, 0.5)
        @testset "$kind, K=$nchunks, $sname, lambda=$lambda" begin
            ls = make_schur_ls(kind, p, scaling; nchunks)
            SecondOrderOptimization.dampen!(ls, lambda, scaling)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
            x_ref = reference_solve(p, lambda, scaling)
            @test norm(ls.x - x_ref) <= 1e-9 * norm(x_ref)
        end
    end

    # Each size alone, including the largest allowed (255) and sizes at the tier boundaries
    for de in (1, 3, 4, 5, 7, 8, 9, 10, 20)
        rng = Random.Xoshiro(de)
        q = SchurTestProblem(rng, [6, 6], [de, de], [[1, 2], [1]])
        for kind in (:dense, :sparse)
            ls = make_schur_ls(kind, q)
            SecondOrderOptimization.dampen!(ls, 0.2)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
            x_ref = reference_solve(q, 0.2, ones(length(q.b)))
            @test norm(ls.x - x_ref) <= 1e-9 * norm(x_ref)
        end
    end

    # A single 255-dimensional eliminated block
    rng = Random.Xoshiro(255)
    big = SchurTestProblem(rng, [3, 3], [255], [[1, 2]])
    for kind in (:dense, :sparse)
        ls = make_schur_ls(kind, big)
        SecondOrderOptimization.dampen!(ls, 0.1)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        x_ref = reference_solve(big, 0.1, ones(length(big.b)))
        @test norm(ls.x - x_ref) <= 1e-8 * norm(x_ref)
    end
end

@testset "Large eliminated blocks: singular blocks are reported, kernels do not allocate (M5)" begin
    for de in (6, 12)   # generic static tier and dynamic tier
        rng = Random.Xoshiro(de)
        q = SchurTestProblem(rng, [6, 6], [de, de], [[1, 2], [1, 2]])
        H = dense_schur_matrix(q)
        # Make eliminated block 2 rank deficient: an outer product of one vector
        st = H.structure
        eo = st.eoffsets[2]
        v = randn(rng, de)
        H.E_data[eo:eo+de^2-1] .= vec(v * v')
        ls = SOOExt.DenseSchurLinearSystem(H, copy(q.b), zeros(length(q.b)))
        SecondOrderOptimization.dampen!(ls, 0.0)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.NotPositiveDefinite
        @test ls.workspace.failed_block[] == 2
        # Damping repairs it
        SecondOrderOptimization.dampen!(ls, 1.0)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
    end

    q = SchurTestProblem(Random.Xoshiro(3), [6, 6], [12, 12, 5, 5], [[1, 2], [1], [2], [1, 2]])
    for kind in (:dense, :sparse)
        ls = make_schur_ls(kind, q; nchunks=1)
        SecondOrderOptimization.dampen!(ls, 0.3)
        SecondOrderOptimization.solve!(ls)
        H, ws = ls.H, ls.workspace
        run1 = if kind === :dense
            () -> reduce_schur_dense!(ls.S, ls.g_S, ls.b_r, ls.b_e, ls.scaling_e, ls.lambda, H.structure, H.E_data, H.C_data, ws)
        else
            () -> reduce_schur_sparse!(ls.S, ls.g_S, ls.b_r, ls.b_e, ls.scaling_e, ls.lambda, H.structure, H.E_data, H.C_data,
                ls.block_colptr, ls.block_rowval, ls.block_row_offsets, ls.col_heights, ws)
        end
        @test run1()
        # The reduction, including the dynamic-dimension blocks, does not allocate
        @test (@allocated run1()) == 0
    end
end

@testset "Persistent CHOLMOD matrix (B5)" begin
    p = standard_problem()
    n = length(p.b)
    ls = make_schur_ls(:sparse, p)
    @test ls.S_chol isa SparseArrays.CHOLMOD.Sparse
    S_chol_before = ls.S_chol
    for lambda in (0.2, 0.9)
        SecondOrderOptimization.dampen!(ls, lambda)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        x_ref = reference_solve(p, lambda, ones(n))
        @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
    end
    @test ls.S_chol === S_chol_before          # refreshed in place, not rebuilt
    tr = SecondOrderOptimization.copy_structure(ls)
    @test tr.S_chol !== ls.S_chol
end

# A gauge-deficient problem: every coupling constrains only the *difference* x_retained[1:3] - x_eliminated, so
# translating all retained and eliminated blocks together changes nothing and H is singular along that direction.
# Dimensions 4:6 of the retained blocks only have a tiny prior, which makes H ill conditioned.
function gauge_problem(seed=21; prior=1e-8)
    rng = Random.Xoshiro(seed)
    r_dims = [6, 6, 6, 6]
    e_dims = [3, 3, 3, 3, 3, 3]
    couplings = [[1, 2], [1, 2, 3], [2, 3, 4], [3, 4], [1, 4], [1, 2, 3, 4]]
    nr_, np_ = sum(r_dims), sum(e_dims)
    H = zeros(nr_ + np_, nr_ + np_)
    for (e, coupled) in enumerate(couplings), r in coupled
        w = 0.5 + rand(rng)
        ci = 6 * (r - 1) .+ (1:3)
        li = nr_ + 3 * (e - 1) .+ (1:3)
        H[ci, ci] .+= w * I(3); H[li, li] .+= w * I(3)
        H[ci, li] .-= w * I(3); H[li, ci] .-= w * I(3)
    end
    for r in 1:4
        ci = 6 * (r - 1) .+ (4:6)
        H[ci, ci] .+= prior * I(3)
    end
    return SchurTestProblem(H, randn(rng, nr_ + np_), r_dims, e_dims, couplings, Tuple{Int, Int}[])
end

@testset "BlockLinearSystemsExt: well-conditioned problems, forward error of x_r and x_e (T1)" begin
    for p in (standard_problem(), coupled_groups_problem(), mixed_dims_problem())
        @test cond(p.H) <= 1e4
        n = length(p.b)
        nr_ = sum(p.r_dims)
        for kind in (:dense, :sparse), solver in (:auto, :cholesky, :ldl), lambda in (0.0, 0.3)
            ls = make_schur_ls(kind, p)
            SecondOrderOptimization.dampen!(ls, lambda)
            @test SecondOrderOptimization.solve!(ls, solver) == SecondOrderOptimization.Success
            x_ref = reference_solve(p, lambda, ones(n))
            @test norm(ls.x_r - x_ref[1:nr_]) <= 1e-10 * norm(x_ref[1:nr_])
            @test norm(ls.x_e - x_ref[nr_+1:end]) <= 1e-10 * norm(x_ref[nr_+1:end])
        end
    end
end

@testset "BlockLinearSystemsExt: gauge-deficient, ill-conditioned problem: relative residual (T1)" begin
    p = gauge_problem()
    n = length(p.b)
    @test cond(p.H) > 1e7
    for kind in (:dense, :sparse), solver in (:auto, :ldl), lambda in (1e-6, 1e-3, 0.1)
        ls = make_schur_ls(kind, p)
        SecondOrderOptimization.dampen!(ls, lambda)
        @test SecondOrderOptimization.solve!(ls, solver) == SecondOrderOptimization.Success
        Hd = p.H + lambda * Diagonal(ones(n))
        rel_res = norm(Hd * ls.x - p.b) / (opnorm(Hd) * norm(ls.x) + norm(p.b))
        @test rel_res <= 1e-13
    end
end

@testset "BlockLinearSystemsExt: no damping drift across rejected trials (T2)" begin
    p = standard_problem()
    n = length(p.b)
    for kind in (:dense, :sparse)
        sc = abs.(diag(p.H))
        ls = make_schur_ls(kind, p, sc)      # Marquardt scaling
        snapshot(H) = (copy(H.E_data), copy(H.C_data), H.R isa Matrix ? copy(H.R) : copy(H.R.data), copy(ls.b), copy(ls.scaling))
        before = snapshot(ls.H)
        lambda0 = 1e-3
        SecondOrderOptimization.dampen!(ls, lambda0, sc)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        x_first = copy(ls.x)
        # 100 increasing damping values, as in a run of rejected trial steps
        for lambda in lambda0 .* 1.5 .^ (1:100)
            SecondOrderOptimization.dampen!(ls, lambda, sc)
            @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        end
        SecondOrderOptimization.dampen!(ls, lambda0, sc)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        @test ls.x == x_first                                   # bit for bit
        @test all(snapshot(ls.H) .== before)                     # R, C, E, b and the scaling are untouched
        @test ls.lambda == lambda0
    end
end

@testset "Sparse Schur system takes its pattern from H (M26)" begin
    p = coupled_groups_problem()
    n = length(p.b)
    H0 = sparse_schur_matrix(p)
    pre = build_schur_pattern(H0.structure; extra_blocks=retained_block_pairs(H0.R))
    Hp = SchurBlockMatrix(H0.structure, H0.R, H0.E_data, H0.C_data; pattern=pre)
    x_ref = reference_solve(p, 0.3, ones(n))
    mk(H) = SecondOrderOptimization.makelinearsystem(nothing, H, :auto)

    # With and without a pattern on H: the same solution
    for H in (H0, Hp)
        ls = mk(H)
        ls.b .= p.b
        SecondOrderOptimization.dampen!(ls, 0.3)
        @test SecondOrderOptimization.solve!(ls) == SecondOrderOptimization.Success
        @test norm(ls.x - x_ref) <= 1e-10 * norm(x_ref)
    end

    # The pattern was used, not rebuilt: its block structure is shared, S is a copy
    ls_a = mk(Hp)
    @test ls_a.block_rowval === pre.block_rowval
    @test ls_a.S !== pre.S_sparse && ls_a.S == pre.S_sparse
    @test mk(H0).block_rowval !== pre.block_rowval
    # ...and building the system does less work than rebuilding the pattern
    mk(Hp); mk(H0)
    @test (@allocated mk(Hp)) < (@allocated mk(H0))

    # Two systems from one H don't share S: solving the first leaves the second's untouched
    ls_b = mk(Hp)
    S_b = copy(ls_b.S)
    S_pre = copy(pre.S_sparse)
    ls_a.b .= p.b
    SecondOrderOptimization.dampen!(ls_a, 0.3)
    @test SecondOrderOptimization.solve!(ls_a) == SecondOrderOptimization.Success
    @test ls_b.S == S_b
    @test pre.S_sparse == S_pre
    @test ls_a.S != S_b   # the first system did write its own S

    # An analysed factor carried by the pattern is reused
    fac = SparseArrays.CHOLMOD.analyze(SparseArrays.CHOLMOD.Sparse(Symmetric(copy(pre.S_sparse), :U)))
    Hf = SchurBlockMatrix(H0.structure, H0.R, H0.E_data, H0.C_data; pattern=merge(pre, (S_factor = fac,)))
    ls_f = mk(Hf)
    @test ls_f.S_factor === fac
    ls_f.b .= p.b
    SecondOrderOptimization.dampen!(ls_f, 0.3)
    @test SecondOrderOptimization.solve!(ls_f) == SecondOrderOptimization.Success
    @test norm(ls_f.x - x_ref) <= 1e-10 * norm(x_ref)

    # The dense system ignores a pattern
    Hd = dense_schur_matrix(p)
    Hdp = SchurBlockMatrix(Hd.structure, Hd.R, Hd.E_data, Hd.C_data; pattern=build_schur_pattern(Hd.structure))
    @test SecondOrderOptimization.makelinearsystem(nothing, Hdp, :auto) isa SOOExt.DenseSchurLinearSystem
end

# Add d to the diagonal of the full matrix a SchurBlockMatrix represents
function add_schur_diag!(H::SchurBlockMatrix, d)
    st = H.structure
    for r in 1:st.nrblocks, i in 1:Int(st.r_dims[r])
        k = st.boffsets_r[r] + i - 1
        if H.R isa Matrix
            H.R[k, k] += d[k]
        else
            block(H.R, r, r)[i, i] += d[k]
        end
    end
    for e in 1:st.neblocks
        de = Int(st.e_dims[e])
        for i in 1:de
            H.E_data[st.eoffsets[e] + (i - 1) * (de + 1)] += d[st.nr + st.boffsets_e[e] + i - 1]
        end
    end
    return H
end

# A quadratic plus a quartic term, so the Hessian H + diag(3x^2) changes every iteration. `kind` is
# :dense or :sparse (a SchurBlockMatrix with that storage of R) or :full (a plain dense Hessian).
function quartic_run(p, kind, linsolver, iterator)
    cost(x) = 0.5 * dot(x, p.H * x) - dot(p.b, x) + 0.25 * sum(xi -> xi^4, x)
    if kind === :full
        Hproto = zeros(length(p.b), length(p.b))
        fdf! = (g, H, x) -> (g .= p.H * x .- p.b .+ x .^ 3; H .= p.H; H[diagind(H)] .+= 3 .* x .^ 2; cost(x))
    else
        Href = kind === :dense ? dense_schur_matrix(p) : sparse_schur_matrix(p)
        Hproto = kind === :dense ? dense_schur_matrix(p) : sparse_schur_matrix(p)
        fdf! = (g, H, x) -> (g .= p.H * x .- p.b .+ x .^ 3; copy_content!(H, Href); add_schur_diag!(H, 3 .* x .^ 2); cost(x))
    end
    traj = CostTrajectory()
    x, res = optimize(fill(3.0, length(p.b)), HessianObjective(cost, fdf!; H = Hproto),
                      OptimizationOptions(; iterator, linsolver, gtol=1e-10); callback=storecostscallback(traj))
    return (; x, res, costs = copy(traj.costs), steps = deepcopy(traj.steps))
end

@testset "Full optimization with a SchurBlockMatrix Hessian: :auto, :cholesky and :ldl (A2)" begin
    p = standard_problem()
    for kind in (:dense, :sparse), it in (:levenbergmarquardt, :levenbergmarquardt_dtd, :newton, :dogleg)
        @testset "$kind, $it" begin
            ra = quartic_run(p, kind, :auto, it)
            rc = quartic_run(p, kind, :cholesky, it)
            rl = quartic_run(p, kind, :ldl, it)
            rf = quartic_run(p, :full, :cholesky, it)
            @test isconverged(ra.res) && isconverged(rl.res)
            @test ra.res.niterations > 3
            # :auto and :cholesky are the same solver for the reduced system: identical iterates
            @test ra.x == rc.x && ra.costs == rc.costs && ra.steps == rc.steps
            # the same optimum as :ldl and as the same problem with a plain dense Hessian
            @test norm(rl.x - ra.x) <= 1e-8 * norm(ra.x)
            @test norm(rf.x - ra.x) <= 1e-8 * norm(ra.x)
            @test ra.res.niterations == rf.res.niterations
        end
    end
end

@testset "Schur systems meet the linear-system interface (A3)" begin
    for (name, p) in (("standard", standard_problem()), ("retained-retained couplings", coupled_groups_problem()),
                      ("mixed eliminated sizes", mixed_dims_problem()))
        n = length(p.b)
        @testset "$name, dense R" begin
            @test check_linear_system(s -> SecondOrderOptimization.makelinearsystem(nothing, dense_schur_matrix(p), s); n, linsolvers=(:auto, :cholesky, :ldl)) === nothing
        end
        @testset "$name, sparse R" begin
            @test check_linear_system(s -> SecondOrderOptimization.makelinearsystem(nothing, sparse_schur_matrix(p), s); n, linsolvers=(:auto, :cholesky, :ldl)) === nothing
        end
    end
    # The helpers read back exactly the full matrix the problem was built from
    p = standard_problem()
    for H in (dense_schur_matrix(p), sparse_schur_matrix(p))
        @test SecondOrderOptimization.conformance_matrix(H) ≈ p.H
    end
end
