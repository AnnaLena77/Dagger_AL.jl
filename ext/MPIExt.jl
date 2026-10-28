module MPIExt

import Dagger
import Dagger: Thunk, Chunk, Processor, MemorySpace
import Dagger: @dagdebug, @opcounter

# Types and generic functions from Dagger that this extension either
# extends with new methods (for MPI-specific types) or calls directly.
import Dagger:
    AbstractAliasing, accelerate!, accel_matches_proc, accel_kind, aliased_object!,
    AliasedObjectCache, AliasedObjectCacheStore, aliasing, aliasing_unwrapped,
    bind_moved_argument,
    chunktype, ChunkView, check_uniform, check_uniformity!, CHECK_UNIFORMITY,
    cleanup_tasks_accel!, constrain, CPURAMMemorySpace,
    current_acceleration, CyclicProcGrid, datasize, default_enabled,
    default_memory_space, default_processor, default_procgrid,
    finalize_acceleration!, execute!, fetch_handle, fire_order_key, get_parent,
    get_processors, gpu_kernel_backend, gpu_memory_kind,
    initialize_acceleration!, inplace_mpi_alloc, inplace_mpi_build,
    inplace_mpi_parts, InvalidScope, ipc_copyto!, ipc_eligible,
    ipc_export, ipc_materialize, IPC_MIN_BYTES, ipc_release!, ipc_type_eligible, is_local,
    istask, LockedObject, memory_space, memory_spaces, MemorySpan,
    memory_spans, move, move!, move_rewrap, move_rewrap_build, DATADEPS_THUNK_ID,
    mpi_device_direct, mpi_device_sync, mpi_library_gpu_aware, mpi_remap_space,
    myid,
    move_rewrap_child_types, move_rewrap_header_mode, move_rewrap_parts,
    move_rewrap_result_type, move_type, multi_span_gather!,
    multi_span_scatter!, next_id, NoAliasing, Options, OSProc,
    partition_affinity_id, post_stage_array_chunks!, processors, ProcessScope, proc_in_scope,
    remotecall_endpoint_toplevel, RemotePtr, root_worker_id, same_node,
    schedule_argument_move, sch_handle, select_processors_uniform!, set_key_stored!,
    set_stored!, short_name, span_len, stage_acquire!, stage_release!,
    stage_to_host!, system_uuid, task_processor_preference, ThreadProc, to_tag,
    tochunk, tochunk_pset, uniform_execution, UnknownAliasing, unwrap,
    unwrap_weak_checked, value_memory_space, WeakChunk, with_context!,
    _with_default_acceleration

import MemPool
import MemPool: DRef, poolget, poolset

# `Base.ScopedValues` only exists on Julia 1.11+; on 1.10 (LTS) fall back to the
# `ScopedValues` package (a Dagger dependency), matching `src/Dagger.jl`.
if !isdefined(Base, :ScopedValues)
    import ScopedValues: ScopedValue, @with, with
else
    import Base.ScopedValues: ScopedValue, @with, with
end

import TaskLocalValues: TaskLocalValue

import Random
import Serialization

using MPI

function check_uniform(value::Integer, original=value)
    CHECK_UNIFORMITY[] && uniform_execution() || return true
    # A rank-local graph is not a world-wide collective
    mpi_world_acceleration() || return true
    comm = MPI.COMM_WORLD
    rank = MPI.Comm_rank(comm)
    matched = compare_all(value, comm)
    if !matched
        if rank == 0
            Core.print("[$rank] Found non-uniform value!\n")
        end
        Core.print("[$rank] value=$value, original=$original\n")
        throw(ArgumentError("Non-uniform value"))
    end
    # N.B. No `MPI.Barrier` here. `compare_all` above already *is* an arrival
    # barrier -- it cannot return until every other rank has entered it and
    # sent -- so a barrier afterwards synchronizes nothing extra, while a
    # blocking one is actively harmful under Dagger's multithreaded runtime:
    #
    #  * `MPI.Barrier` is a blocking `ccall`, so it parks the calling OS thread
    #    inside MPI until every rank arrives. That thread runs no other Julia
    #    task meanwhile -- in particular not `bcast_relay_loop`, the progress
    #    engine other ranks depend on to have a broadcast forwarded.
    #  * Julia cannot see into a plain `ccall`, so the parked thread never
    #    reaches a GC safepoint: any other thread that requests a collection
    #    stalls there until the barrier returns, which takes the relay down with
    #    it even when a second thread was free to run it.
    #
    #    Those two close a real cross-rank cycle. Rank r parks here waiting for
    #    rank s; rank s is waiting on a broadcast whose next hop is r's relay,
    #    which cannot run; so s never reaches this barrier and r never leaves
    #    it. `MPI.Barrier` has no deadlock detection either, so it surfaces as a
    #    CI job silently exhausting its timeout. The P2P inside `compare_all` is
    #    covered by `mpi_deadlock_detect` and yields, so it has neither problem.
    return matched
end

# MPI tag reserved for `compare_all` / `check_uniform` P2P only. It must not
# collide with ordinary Dagger message tags on the same `comm` (which come from
# `to_tag` = thunk/ref IDs, and which `remotecall_endpoint_toplevel` broadcast
# metadata uses `0` for), or ranks steal each other's messages and hang until
# `mpi_deadlock_detect` fires.
#
# Use the top of the MPI tag space (`MPI.tag_ub()`): `take_ref_id!` asserts every
# ordinary tag is strictly `< MPI.tag_ub()`, so this value provably cannot
# collide with one. `tag_ub()` is a valid tag (the MPI standard allows tags in
# `0:MPI_TAG_UB`) and is a library constant identical on every rank, which the
# cross-rank uniformity sends/receives require. (Computed lazily rather than as a
# load-time `const`, since MPI is not yet initialized at module load.)
compare_all_mpi_tag() = UInt32(MPI.tag_ub())

function compare_all(value, comm)
    rank = MPI.Comm_rank(comm)
    size = MPI.Comm_size(comm)
    size == 1 && return true
    tag = compare_all_mpi_tag()
    # Integer checks dominate replicated planning. Every peer receives the
    # exact same serialized value, so build its payload once rather than have
    # MPI.isend serialize it anew for each peer. Keep the general transport for
    # values which may use the raw-parts protocol (e.g. arrays).
    serialized = value isa Integer ? MPI.serialize(value) : nothing
    for i in 0:(size-1)
        if i != rank
            if serialized === nothing
                send_yield(value, comm, i, tag)
            else
                @opcounter :send_yield_serialized
                req = MPI.Isend(serialized, comm; dest=i, tag)
                __wait_for_request(req, comm, rank, i, tag, "send_yield", "send")
            end
        end
    end
    match = true
    for i in 0:(size-1)
        if i != rank
            other_value = recv_yield(comm, i, tag)
            if value != other_value
                match = false
            end
        end
    end
    return match
end

"""
    sync_mpi_rng!(comm)

Broadcast a seed from rank 0 and `Random.seed!` it on every rank so default
RNGs are coherent under SPMD MPI acceleration.
"""
function sync_mpi_rng!(comm::MPI.Comm)
    seed = Ref{UInt64}(0)
    if MPI.Comm_rank(comm) == 0
        seed[] = rand(Random.RandomDevice(), UInt64)
    end
    MPI.Bcast!(seed, 0, comm)
    Random.seed!(seed[])
    return seed[]
end

"""
    check_mpi_rng_coherent!(comm)

Probe `rand(UInt64)` on every rank and throw if any rank differs. Always runs
(independent of `CHECK_UNIFORMITY[]`) because coherent RNGs are required for
SPMD correctness after MPI acceleration init.
"""
function check_mpi_rng_coherent!(comm::MPI.Comm)
    probe = rand(UInt64)
    if !compare_all(probe, comm)
        throw(ArgumentError("Non-uniform RNG under MPI acceleration"))
    end
    return true
end

struct MPIAcceleration <: Dagger.Acceleration
    comm::MPI.Comm
end
MPIAcceleration() = MPIAcceleration(MPI.COMM_WORLD)

# Whether the acceleration of the current task spans every rank (is not a rank-local graph)
mpi_world_acceleration() = (a = Dagger.current_acceleration(); !(a isa MPIAcceleration) || a.comm == MPI.COMM_WORLD)

aliasing(accel::MPIAcceleration, x::Chunk, T) =
    Dagger.memoized_chunk_aliasing(() -> _aliasing_bcast(accel, x, T), x, T)

"""
    mpi_ainfo_owner(x) -> Int

The rank whose copy of `x` is the one that can be inspected to derive its
aliasing info, or `-1` when every rank can answer for itself.

`-1` covers data that no single rank owns: a plain value, or a `Chunk` created
under a temporary `DistributedAcceleration` (or on a worker thread that did not
inherit the MPI TLS) and therefore carrying a `DRef` rather than an `MPIRef`.
"""
mpi_ainfo_owner(x::Chunk) = x.handle isa MPIRef ? x.handle.rank : -1
mpi_ainfo_owner(@nospecialize(x)) = -1

# `x`'s aliasing info as its owner sees it, stamped with the owning rank so that
# spans from different ranks -- whose SPMD heaps have very similar address
# layouts -- can never appear to alias each other.
function mpi_owner_ainfo(@nospecialize(x), dep_mod, owner::Int)
    ainfo = _with_default_acceleration() do
        mpi_raw_aliasing(x, dep_mod)
    end
    return owner < 0 ? ainfo : mpi_remap_ainfo(ainfo, owner)
end

# How to read the local aliasing info out of each kind of handle. Runs under the
# default acceleration (see `mpi_owner_ainfo`), on the owning rank only.
mpi_raw_aliasing(@nospecialize(x), dep_mod) = aliasing(x, dep_mod)

"""
    _aliasing_bcast(accel::MPIAcceleration, x, dep_mod)

The owner computes `x`'s aliasing info and broadcasts it; every other rank
receives it. All ranks must call this at the same logical point, since it is a
collective.

Prefer letting Phase 1 resolve a whole region's arguments in one exchange
(`batch_aliasing`) and reading the results back out of the region memo; this
per-argument form is the fallback for arguments the batch did not cover.
"""
function _aliasing_bcast(accel::MPIAcceleration, @nospecialize(x), dep_mod)
    owner = mpi_ainfo_owner(x)
    if owner < 0
        return _with_default_acceleration() do
            mpi_raw_aliasing(x, dep_mod)
        end
    end
    tag = to_tag()
    check_uniform(tag)
    rank = MPI.Comm_rank(accel.comm)
    ainfo = if owner == rank
        @opcounter :aliasing_bcast_send_yield
        bcast_yield(accel.comm, owner, tag, mpi_owner_ainfo(x, dep_mod, owner))
    else
        bcast_yield(accel.comm, owner, tag)
    end
    check_uniform(ainfo)
    return ainfo
end

"""
    batch_aliasing(accel::MPIAcceleration, arg_ws)

Resolve a whole batch of arguments' aliasing info in one exchange per owning
rank, instead of one broadcast per argument.

Replicated planning makes every per-argument `aliasing` call a rendezvous: a rank
that reaches argument `i` waits there until all its peers do, so a region's
planning becomes a chain of `nargs` round-trips whose length grows with both the
region and the rank count. The batch is a *uniform* list -- every rank walks the
same arguments in the same order -- so an index into it names the same argument
everywhere, which is all that is needed to exchange the answers wholesale: each
owning rank broadcasts the ainfos for its own arguments keyed by index.

The results also seed the region's aliasing memo, so the rest of planning (slot
generation, remainder computation, the write-back epilogue) finds them already
answered and communicates no further.
"""
function Dagger.batch_aliasing(accel::MPIAcceleration, arg_ws::Vector{Dagger.ArgumentWrapper})
    n = length(arg_ws)
    n == 0 && return Pair{Dagger.ArgumentWrapper,Dagger.AliasingWrapper}[]
    objs = Any[arg_w.arg for arg_w in arg_ws]
    dep_mods = Any[arg_w.dep_mod for arg_w in arg_ws]
    ainfos = Dagger.batch_ainfos(accel, objs, dep_mods)
    return Pair{Dagger.ArgumentWrapper,Dagger.AliasingWrapper}[
        arg_ws[i] => Dagger.AliasingWrapper(ainfos[i]) for i in 1:n]
end

"""
    batch_ainfos(accel::MPIAcceleration, objs, dep_mods)

One exchange per owning rank for a whole batch of objects, instead of one
broadcast each. See `batch_aliasing` above for why this shape matters.
"""
function Dagger.batch_ainfos(accel::MPIAcceleration, objs::Vector, dep_mods::Vector)
    n = length(objs)
    n == 0 && return AbstractAliasing[]
    comm = accel.comm
    rank = MPI.Comm_rank(comm)
    check_uniform(UInt64(n))
    timing = Dagger.HIER_TIMING[]
    t0 = timing ? time_ns() : UInt64(0)

    owners = Vector{Int}(undef, n)
    ainfos = Vector{Union{Nothing,AbstractAliasing}}(nothing, n)
    mine = Dict{Int,AbstractAliasing}()
    for i in 1:n
        owner = mpi_ainfo_owner(objs[i])
        owners[i] = owner
        if owner < 0
            # Answerable on every rank, so nothing to exchange
            ainfos[i] = mpi_owner_ainfo(objs[i], dep_mods[i], owner)
        elseif owner == rank
            mine[i] = mpi_owner_ainfo(objs[i], dep_mods[i], owner)
        end
    end

    # `owners` is itself uniform, so every rank knows which ranks have something
    # to say and skips the rest: one broadcast per *contributing* rank.
    roots = sort!(unique!(filter(>=(0), copy(owners))))
    for root in roots
        tag = to_tag()
        check_uniform(tag)
        received = if root == rank
            @opcounter :aliasing_bcast_send_yield
            bcast_yield(comm, root, tag, mine)
        else
            bcast_yield(comm, root, tag)
        end::Dict{Int,AbstractAliasing}
        for (i, ainfo) in received
            ainfos[i] = ainfo
        end
    end

    results = Vector{AbstractAliasing}(undef, n)
    for i in 1:n
        ainfo = ainfos[i]
        if ainfo === nothing
            error("batch_ainfos: rank $rank received no aliasing info for object $i (owner $(owners[i]))")
        end
        # Take back whatever the memo now holds, so this batch and every later
        # lookup of the same object agree even if an entry was already there.
        results[i] = Dagger.memoize_ainfo!(Dagger.ainfo_memo_key(objs[i], dep_mods[i]), ainfo)
    end
    timing && Dagger.hier_log!(Dagger.LogHierAinfo, 0x01, Dagger.LogHierAinfoId(), (time_ns() - t0, n))
    return results
end

default_processor(accel::MPIAcceleration) = MPIOSProc(accel.comm, 0)
default_processor(accel::MPIAcceleration, x) = MPIOSProc(accel.comm, 0)
default_processor(accel::MPIAcceleration, x::Chunk) = MPIOSProc(x.handle.comm, x.handle.rank)
default_processor(accel::MPIAcceleration, x::Function) = MPIOSProc(accel.comm, MPI.Comm_rank(accel.comm))
default_processor(accel::MPIAcceleration, T::Type) = MPIOSProc(accel.comm, MPI.Comm_rank(accel.comm))
uniform_execution(accel::MPIAcceleration) = true
accel_kind(::MPIAcceleration) = :mpi

# Children / uniform-processor caches are shared across reusable scheduler
# tasks. Protect both with one lock; never mutate them unlocked.
const MPI_PROC_CACHE_LOCK = Threads.ReentrantLock()
const MPIClusterProcChildren = Dict{MPI.Comm, Set{Processor}}()
# Keyed by (comm, ambient compute scope): the uniform listing depends on which
# processors the current scope admits (see `uniform_mpi_processors`), not just
# on the communicator.
const MPIUniformProcsCache = Dict{Tuple{MPI.Comm, Dagger.AbstractScope}, Vector{Processor}}()

# Drop every cached uniform listing for `comm`, across all scopes.
function invalidate_uniform_cache!(comm::MPI.Comm)
    for key in collect(keys(MPIUniformProcsCache))
        key[1] == comm && delete!(MPIUniformProcsCache, key)
    end
end

struct MPIClusterProc <: Processor
    comm::MPI.Comm
    function MPIClusterProc(comm::MPI.Comm)
        ensure_children!(comm)
        return new(comm)
    end
end

Dagger.Sch.init_proc(state, proc::MPIClusterProc, log_sink) = Dagger.Sch.init_proc(state, MPIOSProc(proc.comm), log_sink)

MPIClusterProc() = MPIClusterProc(MPI.COMM_WORLD)

# Populate `MPIClusterProcChildren[comm]` once. Safe on the scheduler hot path;
# does not clear the uniform-processor cache on every lookup.
function ensure_children!(comm::MPI.Comm)
    # `@lock` (not `lock(...) do`) so the early `return` on a cache hit actually
    # returns from `ensure_children!`; inside a `do` closure it would only
    # return from the closure and we'd needlessly re-fetch the children below.
    @lock MPI_PROC_CACHE_LOCK begin
        haskey(MPIClusterProcChildren, comm) && return MPIClusterProcChildren[comm]
    end
    # Fetch outside the lock: `get_processors(OSProc())` may remotecall / take
    # OSPROC_PROCESSOR_CACHE and must not run under MPI_PROC_CACHE_LOCK.
    children = get_processors(OSProc())
    @lock MPI_PROC_CACHE_LOCK begin
        if !haskey(MPIClusterProcChildren, comm)
            MPIClusterProcChildren[comm] = children
            # Invalidate only this communicator's uniform listing
            invalidate_uniform_cache!(comm)
        end
        return MPIClusterProcChildren[comm]
    end
end

# Force-refresh children for `comm` (e.g. after processor callbacks change).
function populate_children!(comm::MPI.Comm)
    children = get_processors(OSProc())
    lock(MPI_PROC_CACHE_LOCK) do
        MPIClusterProcChildren[comm] = children
        invalidate_uniform_cache!(comm)
    end
    return children
end

function uniform_mpi_processors(accel::MPIAcceleration)
    # Ensure children first so the `get!` callback never mutates this Dict
    # mid-insertion (via MPIClusterProc / ensure_children!).
    ensure_children!(accel.comm)
    # `get_compute_scope()` reflects the ambient `with_options(scope=...)` at
    # the call site (e.g. inside `stage(::AllocateArray)`), so it must be read
    # outside the cache lookup closure, not memoized away with the comm alone.
    scope = Dagger.get_compute_scope()
    lock(MPI_PROC_CACHE_LOCK) do
        get!(MPIUniformProcsCache, (accel.comm, scope)) do
            children = MPIClusterProcChildren[accel.comm]
            procs = Processor[]
            for i in 0:(MPI.Comm_size(accel.comm)-1)
                for innerProc in children
                    push!(procs, MPIProcessor(innerProc, accel.comm, i))
                end
            end
            # Default placement only targets processors the ambient scope
            # admits. With no explicit scope this is `DefaultScope()`, which
            # (via its `DefaultEnabledTaint`) keeps today's CPU-only behavior;
            # GPU processors remain opt-in, but now via *either* an explicit
            # `assignment` array or a GPU-restricting `with_options(scope=...)`
            # (e.g. `all_gpu_scope`) — previously only the former worked, so
            # allocations made without an explicit assignment (bare `rand`,
            # `similar` on an operation's result, ...) silently fell back to
            # CPU even inside a GPU-only scope.
            filter!(p -> Dagger.proc_in_scope(p, scope), procs)
            select_processors_uniform!(procs, accel)
            procs
        end
    end
end

struct MPIOSProc <: Processor
    comm::MPI.Comm
    rank::Int
end

function MPIOSProc(comm::MPI.Comm)
    rank = MPI.Comm_rank(comm)
    return MPIOSProc(comm, rank)
end

function MPIOSProc()
    return MPIOSProc(MPI.COMM_WORLD)
end

ProcessScope(p::MPIOSProc) = ProcessScope(myid())

function check_uniform(proc::MPIOSProc, original=proc)
    return check_uniform(hash(MPIOSProc), original) &&
           check_uniform(proc.rank, original)
end

function memory_spaces(proc::MPIOSProc)
    children = get_processors(proc)
    spaces = Set{MemorySpace}()
    for proc in children
        for space in memory_spaces(proc)
            push!(spaces, space)
        end
    end
    return spaces
end

struct MPIProcessScope <: Dagger.AbstractScope
    comm::MPI.Comm
    rank::Int
end

Base.isless(::MPIProcessScope, ::MPIProcessScope) = false
Base.isless(::MPIProcessScope, ::Dagger.ProcessScope) = true
Base.isless(::MPIProcessScope, ::Dagger.NodeScope) = true
Base.isless(::MPIProcessScope, ::Dagger.UnionScope) = true
Base.isless(::MPIProcessScope, ::Dagger.TaintScope) = true
Base.isless(::MPIProcessScope, ::Dagger.AnyScope) = true
Base.isless(::Dagger.ProcessScope, ::MPIProcessScope) = false
Base.isless(::Dagger.NodeScope, ::MPIProcessScope) = false
constrain(x::MPIProcessScope, y::MPIProcessScope) =
    x == y ? y : InvalidScope(x, y)
# Under MPI, every processor reports root_worker_id == myid(), so a local
# ProcessScope intersects any MPIProcessScope as the more specific rank scope
constrain(x::Dagger.ProcessScope, y::MPIProcessScope) =
    x.wid == myid() ? y : InvalidScope(x, y)
constrain(x::Dagger.NodeScope, y::MPIProcessScope) =
    x == Dagger.NodeScope() ? y : Dagger.InvalidScope(x, y)

Base.isless(::Dagger.ExactScope, ::MPIProcessScope) = true
constrain(x::MPIProcessScope, y::Dagger.ExactScope) =
    (y.processor isa MPIProcessor &&
     y.processor.comm == x.comm &&
     y.processor.rank == x.rank) ? y : Dagger.InvalidScope(x, y)

function enclosing_scope(proc::MPIOSProc)
    return MPIProcessScope(proc.comm, proc.rank)
end

function Dagger.to_scope(::Val{:mpi_rank}, sc::NamedTuple)
    if sc.mpi_rank == Colon()
        return Dagger.to_scope(Val{:mpi_ranks}(), merge(sc, (;mpi_ranks=Colon())))
    else
        @assert sc.mpi_rank isa Integer "Expected a single MPI rank for :mpi_rank, got $(sc.mpi_rank)\nConsider using :mpi_ranks instead."
        return Dagger.to_scope(Val{:mpi_ranks}(), merge(sc, (;mpi_ranks=[sc.mpi_rank])))
    end
end
Dagger.scope_key_precedence(::Val{:mpi_rank}) = 2
function Dagger.to_scope(::Val{:mpi_ranks}, sc::NamedTuple)
    comm = get(sc, :mpi_comm, MPI.COMM_WORLD)
    # `:mpi_ranks` is `Colon()` to select every rank, otherwise an iterable of
    # rank indices. (`mpi_rank=r` funnels through here as `mpi_ranks=[r]`.)
    if sc.mpi_ranks == Colon()
        ranks = 0:(MPI.Comm_size(comm)-1)
    else
        ranks = sc.mpi_ranks
    end
    scopes = Dagger.ExactScope[]
    for rank in ranks
        procs = Dagger.get_processors(MPIOSProc(comm, rank))
        rank_scope = MPIProcessScope(comm, rank)
        for proc in procs
            proc_scope = Dagger.ExactScope(proc)
            constrain(proc_scope, rank_scope) isa Dagger.InvalidScope && continue
            push!(scopes, proc_scope)
        end
    end
    return Dagger.UnionScope(scopes)
end
Dagger.scope_key_precedence(::Val{:mpi_ranks}) = 2

"""
    Dagger.gpu_scope(DeviceProc::Type{<:Processor}, dev_id::Function, dev_ids, sc::NamedTuple, ::Val{:mpi}) -> AbstractScope

MPI-specific method of `Dagger.gpu_scope` (dispatched via `Val{:mpi}`, either
because `sc` has `mpi_rank`/`mpi_ranks`, or because `accel_kind(current_acceleration())
== :mpi`). Restricts to `sc.mpi_rank`/`sc.mpi_ranks` when present (GPU key +
`mpi_rank`/`mpi_ranks` combined in one `scope()` call), otherwise every rank
of `sc.mpi_comm`/`MPI.COMM_WORLD` (GPU key alone, under MPI acceleration).
"""
function Dagger.gpu_scope(DeviceProc::Type{<:Processor}, dev_id::Function, dev_ids, sc::NamedTuple, ::Val{:mpi})
    comm = get(sc, :mpi_comm, MPI.COMM_WORLD)
    ranks = if haskey(sc, :mpi_rank)
        [sc.mpi_rank]
    elseif haskey(sc, :mpi_ranks)
        sc.mpi_ranks == Colon() ? (0:(MPI.Comm_size(comm)-1)) : sc.mpi_ranks
    else
        0:(MPI.Comm_size(comm)-1)
    end
    scopes = Dagger.ExactScope[]
    for rank in ranks
        for proc in Dagger.get_processors(MPIOSProc(comm, rank))
            proc isa MPIProcessor || continue
            proc.innerProc isa DeviceProc || continue
            if dev_ids == Colon() || dev_id(proc.innerProc) in dev_ids
                push!(scopes, Dagger.ExactScope(proc))
            end
        end
    end
    return Dagger.UnionScope(scopes)
end

struct MPIProcessor{P<:Processor} <: Processor
    innerProc::P
    comm::MPI.Comm
    rank::Int
end
proc_in_scope(proc::Processor, scope::MPIProcessScope) = false
proc_in_scope(proc::MPIProcessor, scope::MPIProcessScope) =
    proc.comm == scope.comm && proc.rank == scope.rank

function check_uniform(proc::MPIProcessor, original=proc)
    return check_uniform(hash(MPIProcessor), original) &&
           check_uniform(proc.rank, original) &&
           # Compare the logical identity (kind + ordinal), not the raw struct:
           # device handles/UUIDs of GPU processors are rank-local
           check_uniform(hash(short_name(proc.innerProc)), original)
end

Dagger.iscompatible_func(::MPIProcessor, opts, ::Any) = true
Dagger.iscompatible_arg(::MPIProcessor, opts, ::Any) = true

# Under uniform (SPMD) execution every rank must run each task on the rank it
# was deterministically scheduled to; local work stealing would diverge
Dagger.Sch.stealing_permitted(::MPIProcessor) = false

# The thread that plans a Datadeps region is thread 1 of every rank (the main task's)
Dagger.is_driver_thread_proc(p::MPIProcessor) = p.innerProc isa Dagger.ThreadProc && p.innerProc.tid == 1

default_enabled(proc::MPIProcessor) = default_enabled(proc.innerProc)

Dagger.supports_lapack_panel(proc::MPIProcessor) = Dagger.supports_lapack_panel(proc.innerProc)

# `@stencil`'s inner kernel dispatches on concrete processor types (ThreadProc,
# GPU procs); MPIProcessor is a rank-local wrapper around one of those, so
# forward to whatever it wraps rather than adding an MPI-specific sweep.
Dagger.inner_stencil_proc!(proc::MPIProcessor, f, output, read_vars) =
    Dagger.inner_stencil_proc!(proc.innerProc, f, output, read_vars)

root_worker_id(proc::MPIProcessor) = myid()
root_worker_id(proc::MPIOSProc) = myid()
root_worker_id(proc::MPIClusterProc) = myid()

get_parent(proc::MPIClusterProc) = proc
get_parent(proc::MPIOSProc) = MPIClusterProc(proc.comm)
get_parent(proc::MPIProcessor) = MPIOSProc(proc.comm, proc.rank)

# Rank-deterministic keys: default fire_order_key uses root_worker_id, which
# is always myid() for MPI processors and is not comparable across ranks.
function fire_order_key(proc::MPIClusterProc)
    wid = root_worker_id(proc)
    return (wid, wid)
end
fire_order_key(proc::MPIOSProc) = (proc.rank, 0)
fire_order_key(proc::MPIProcessor) = (get_parent(proc).rank, proc.rank)

function task_processor_preference(accel::MPIAcceleration, task::Thunk, state)
    # N.B. inputs[1] is the function, whose chunk (when wrapped) is deliberately
    # owned by the local rank on every rank — only data arguments carry
    # rank-uniform ownership
    for arg in task.inputs[2:end]
        arg_value = unwrap_weak_checked(Dagger.value(arg))
        arg_chunk = if istask(arg_value)
            Dagger.Sch.load_result(state, arg_value)
        elseif arg_value isa Chunk
            arg_value
        else
            nothing
        end
        if arg_chunk isa Chunk && arg_chunk.handle isa MPIRef
            return arg_chunk.handle.rank
        end
    end
    return nothing
end

short_name(proc::MPIProcessor) = "(MPI: $(proc.rank), $(short_name(proc.innerProc)))"

function get_processors(mosProc::MPIOSProc)
    children = ensure_children!(mosProc.comm)
    mpiProcs = Set{Processor}()
    for proc in children
        push!(mpiProcs, MPIProcessor(proc, mosProc.comm, mosProc.rank))
    end
    return mpiProcs
end

#TODO: non-uniform ranking through MPI groups
#TODO: use a lazy iterator
function get_processors(proc::MPIClusterProc)
    children = ensure_children!(proc.comm)
    result = Set{Processor}()
    for i in 0:(MPI.Comm_size(proc.comm)-1)
        for innerProc in children
            push!(result, MPIProcessor(innerProc, proc.comm, i))
        end
    end
    return result
end

struct MPIMemorySpace{S<:MemorySpace} <: MemorySpace
    innerSpace::S
    comm::MPI.Comm
    rank::Int
end

function Base.:(==)(a::MPIMemorySpace, b::MPIMemorySpace)
    return a.innerSpace == b.innerSpace &&
           a.comm == b.comm &&
           a.rank == b.rank
end
# N.B. Not `space.comm.val`: that is the raw MPI handle, which is a small integer in MPICH
# but a pointer in Open MPI, so it differs from process to process and made every
# uniformity check on a collection of spaces (hash of a Vector{MemorySpace}) report
# divergence between ranks that agree. `==` still distinguishes communicators.
Base.hash(space::MPIMemorySpace, h::UInt=UInt(0)) =
    hash(space.innerSpace, hash(space.rank, hash(MPIMemorySpace, h)))

function check_uniform(space::MPIMemorySpace, original=space)
    return check_uniform(space.rank, original) &&
           # Compare the logical identity (kind + ordinal), not the raw struct:
           # device handles/UUIDs of GPU memory spaces are rank-local
           check_uniform(hash(short_name(space.innerSpace)), original)
end

short_name(space::MPIMemorySpace) = "(MPI: $(space.rank), $(short_name(space.innerSpace)))"

default_processor(space::MPIMemorySpace) = MPIOSProc(space.comm, space.rank)
default_memory_space(accel::MPIAcceleration) = MPIMemorySpace(CPURAMMemorySpace(myid()), accel.comm, 0)

default_memory_space(accel::MPIAcceleration, x) = MPIMemorySpace(value_memory_space(x), accel.comm, 0)
default_memory_space(accel::MPIAcceleration, x::Chunk) = MPIMemorySpace(CPURAMMemorySpace(myid()), x.handle.comm, x.handle.rank)
default_memory_space(accel::MPIAcceleration, x::Function) = MPIMemorySpace(CPURAMMemorySpace(myid()), accel.comm, MPI.Comm_rank(accel.comm))
default_memory_space(accel::MPIAcceleration, T::Type) = MPIMemorySpace(CPURAMMemorySpace(myid()), accel.comm, MPI.Comm_rank(accel.comm))

function memory_spaces(proc::MPIClusterProc)
    rawMemSpace = Set{MemorySpace}()
    for rnk in 0:(MPI.Comm_size(proc.comm) - 1)
        for innerSpace in memory_spaces(OSProc())
            push!(rawMemSpace, MPIMemorySpace(innerSpace, proc.comm, rnk))
        end
    end
    return rawMemSpace
end

function memory_spaces(proc::MPIProcessor)
    rawMemSpace = Set{MemorySpace}()
    for innerSpace in memory_spaces(proc.innerProc)
        push!(rawMemSpace, MPIMemorySpace(innerSpace, proc.comm, proc.rank))
    end
    return rawMemSpace
end

root_worker_id(mem_space::MPIMemorySpace) = myid()
# Hierarchical Datadeps partitions by this id (analogous to Distributed worker
# id). MPI always reports `root_worker_id == myid()`, so affinity must key on
# the owning rank instead.
partition_affinity_id(space::MPIMemorySpace) = space.rank
partition_affinity_id(proc::MPIProcessor) = proc.rank
partition_affinity_id(proc::MPIOSProc) = proc.rank

function processors(memSpace::MPIMemorySpace)
    # The sorted list of a space never changes (processors are fixed once the
    # acceleration is up), and building it sorts by `short_name` strings: 1.2 us
    # and 63 allocations per call at 4 threads, 23 us and 1086 at 16 (laptop), on
    # paths that run several times per task (`first(processors(space))` in
    # planning, copies and frees). So it is built once per space; each call gets
    # a copy, because callers may modify what they receive.
    cached = get((@atomic MPI_SPACE_PROCS.table), memSpace, nothing)
    cached === nothing || return copy(cached::Vector{Processor})
    rawProc = Processor[]
    for innerProc in processors(memSpace.innerSpace)
        push!(rawProc, MPIProcessor(innerProc, memSpace.comm, memSpace.rank))
    end
    # Return a deterministically-ordered vector rather than a `Set`: callers pick
    # the owner processor with `first(processors(space))`, and that choice must be
    # identical on every rank for SPMD uniformity. `Set` iterates in hash order,
    # which is not guaranteed to agree across separately-launched ranks (an
    # `MPIProcessor` embeds an identity-hashed `MPI.Comm`, so its hash — and thus
    # the set's iteration order — can differ per process). Sort by the same
    # rank-uniform identity (`short_name` of the inner processor) used by
    # `check_uniform`.
    sort!(rawProc; by=p->short_name(p.innerProc))
    lock(MPI_SPACE_PROCS_LOCK) do
        table = copy(@atomic MPI_SPACE_PROCS.table)
        table[memSpace] = rawProc
        @atomic MPI_SPACE_PROCS.table = table
    end
    return copy(rawProc)
end
# Read without a lock: the table is replaced as a whole
mutable struct MPISpaceProcsCache
    @atomic table::Dict{MPIMemorySpace,Vector{Processor}}
end
const MPI_SPACE_PROCS = MPISpaceProcsCache(Dict{MPIMemorySpace,Vector{Processor}}())
const MPI_SPACE_PROCS_LOCK = ReentrantLock()

struct MPIRefID
    # 64 bit: the ids of a group graph live above MPI_GROUP_ID_BASE (2^40)
    tid::UInt64
    generic::Bool
    id::UInt64
    function MPIRefID(tid, generic, id)
        @assert tid > 0 || generic "Invalid MPIRefID: tid=$tid, generic=$generic, id=$id"
        return new(tid, generic, id)
    end
end
Base.hash(id::MPIRefID, h::UInt=UInt(0)) =
    hash(id.tid, hash(id.generic, hash(id.id, hash(MPIRefID, h))))

function check_uniform(ref::MPIRefID, original=ref)
    return check_uniform(ref.tid, original) &&
           check_uniform(ref.generic, original) &&
           check_uniform(ref.id, original)
end

function to_tag()
    if Dagger.in_task()
        # Tag is already assigned
        opts = Dagger.get_tls().task_spec.options
        tag = opts.tag
        if tag !== nothing
            return tag
        end
        # Tasks spawned outside the datadeps queue may not have a tag option;
        # derive a uniform tag from the thunk ID instead
        return to_tag(take_ref_id!())
    end

    # Generate a tag based on the TID
    @assert !Dagger.Sch.SCHED_MOVE[] "We should not create a tag during Sch move"
    return to_tag(take_ref_id!())
end
# Ids of a group graph (a communicator of k ranks, see "Group graphs") live above MPI_GROUP_ID_BASE and
# are unique per process across groups; a message on a communicator never mixes with one on another, so
# only the counter part of the id (the low bits) has to be a valid, group-uniform tag.
const MPI_GROUP_ID_BASE = 1 << 40
const MPI_GROUP_TAG_MASK = (1 << 22) - 1
mpi_tag_of(x::Integer) = x >= MPI_GROUP_ID_BASE ? Int(x & MPI_GROUP_TAG_MASK) : Int(x)
to_tag(id::MPIRefID) = id.generic ? mpi_tag_of(id.id) : mpi_tag_of(id.tid)

# DATADEPS_THUNK_ID (current task uid for deterministic MPIRefID generation) is owned by
# core Dagger (src/datadeps/queue.jl) and imported below; core datadeps sets it
# and this extension reads it.
# Private internal value for tracking TID-based ID generations
# N.B. Sub-counters are keyed by TID: every rank allocates IDs for a given TID
# in the same deterministic order (sequential SPMD planning, or the fixed
# tochunk sequence within a thunk), so the resulting MPIRefIDs are uniform.
const _MPIREF_TID = LockedObject(Dict{Int,Int}())

mutable struct MPIRef
    comm::MPI.Comm
    rank::Int
    size::Int
    innerRef::Union{DRef, Nothing}
    id::MPIRefID
end
Base.hash(ref::MPIRef, h::UInt=UInt(0)) = hash(ref.rank, hash(ref.id, hash(MPIRef, h)))
root_worker_id(ref::MPIRef) = myid()

function check_uniform(ref::MPIRef, original=ref)
    return check_uniform(ref.rank, original) &&
           check_uniform(ref.id, original)
end

function unwrap(handle::MPIRef)
    @assert handle.rank == MPI.Comm_rank(handle.comm) "MPIRef $handle is not owned by this rank: $(handle.rank) != $(MPI.Comm_rank(handle.comm))"
    return unwrap(handle.innerRef)
end

# An MPIRef's data is only inspectable on the rank that owns it; other ranks
# must not attempt to `unwrap`/`aliasing` it during (rank-uniform) planning.
to_tag(ref::MPIRef) = to_tag(ref.id)

move(from_proc::Processor, to_proc::Processor, x::MPIRef) =
    move(from_proc, to_proc, poolget(x; uniform=uniform_execution()))

# Read the size carried on the MPIRef itself: `innerRef` only exists on the
# owning rank, so querying it there would report 0 everywhere else. Non-owning
# ranks hold a placeholder (size 0) since they never see the value at
# construction; this residual per-rank difference is harmless because `datasize`
# only feeds cost-based placement, which uniform (MPI) execution overrides via
# `select_processors_uniform!` (see estimate_task_costs! / schedule!).
datasize(x::MPIRef) = x.size

next_ref_sub_id!(tid) =
    lock(_MPIREF_TID) do counters
        counters[tid] = get(counters, tid, 0) + 1
    end

# Forget completed tasks' ref-ID sub-counters: a finished task generates no
# further IDs, and without cleanup the table grows with every task for the
# whole session. Reclaim at wait_all (datadeps region end) after execution —
# planning (DATADEPS_THUNK_ID=>uid) and in-task tochunk share the same TID key (eager
# uid == thunk id), so reclaiming between planning and execution would collide
# on sub-ids. Rank-local and timing-independent: only handed-out values matter
# for uniformity, and TIDs never recur (monotonic shared counter). Deferral
# does not exhaust MPI tags (tags track monotonic TIDs / hashed (tid,sub)).
mpi_cleanup_tid(tid::Integer) =
    lock(_MPIREF_TID) do counters
        delete!(counters, Int(tid))
    end

function mpi_cleanup_tids!(tids)
    lock(_MPIREF_TID) do counters
        for tid in tids
            delete!(counters, Int(tid))
        end
    end
end

cleanup_tasks_accel!(::MPIAcceleration, tasks) =
    mpi_cleanup_tids!(Iterators.map(t -> Int(t.uid), tasks))

function schedule_argument_move(::MPIAcceleration, thunk_id::Integer, f::Function)
    with(DATADEPS_THUNK_ID => Int64(thunk_id)) do
        f()
    end
    return nothing
end

# MPI is the only backend that observes SCHED_MOVE inside moves (to suppress
# tag creation); the default acceleration performs the move with no scope.
Dagger.sched_move(::MPIAcceleration, to_proc, @nospecialize(value)) =
    with(() -> Dagger.move(to_proc, value), Dagger.Sch.SCHED_MOVE => true)

function take_ref_id!()
    tid = 0
    generic = 0
    id = 0
    if Dagger.in_task()
        tid = sch_handle().thunk_id.id
        id = next_ref_sub_id!(tid)
    elseif (dtid = DATADEPS_THUNK_ID[]) != 0
        # One lookup: a scoped value is a walk of the scope chain, and this runs for every task
        tid = dtid
        id = next_ref_sub_id!(tid)
    else
        if current_task() !== Base.roottask
            throw(ConcurrencyViolationError("Attempted to generate generic MPIRefID in a multi-threaded context"))
        end
        generic = true
        accel = Dagger.current_acceleration()
        if accel isa MPIAcceleration && accel.comm != MPI.COMM_WORLD
            # A rank-local graph (a Datadeps planner running in it, say) must not draw from the
            # counter the world's uniform generic ids come from: the ranks run different numbers
            # of local operations, and the world's ids would stop agreeing
            id = Int(Dagger.eager_next_id(accel))
        else
            id = next_id() # Abuse the TID counter for generic IDs
            check_uniform(id)
        end
    end
    # Only the tag-relevant component must fit in an MPI tag
    # N.B. Skip when MPI is uninitialized (e.g. pure-Distributed callers)
    # N.B. Ids of a rank-local graph start above the tag range (they never become tags)
    @assert !MPI.Initialized() || (generic == true ? id : tid) >= MPI_LOCAL_ID_BASE || (generic == true ? id : tid) < MPI.tag_ub()
    return MPIRefID(tid, generic, id)
end

#TODO: partitioned scheduling with comm bifurcation
# N.B. `type=` is for the Chunk's metadata only (MemPool.poolset does not accept it), so it is
# taken as its own keyword rather than filtered out of `kwargs`: rebuilding the NamedTuple
# through a generator cost ~650 ns and 7 allocations per call (laptop; 826 -> 182 ns), and
# every MPI task result goes through here
function tochunk_pset(x, space::MPIMemorySpace; device=nothing, force_nonlocal=false, type=nothing, kwargs...)
    @assert space.comm == MPI.COMM_WORLD || MPI.Comm_size(space.comm) == 1 || mpi_is_group(space.comm) "$(space.comm) is neither the world, a rank-local communicator nor a registered group"
    local_rank = MPI.Comm_rank(space.comm)
    Mid = take_ref_id!()
    if local_rank != space.rank || force_nonlocal
        return MPIRef(space.comm, space.rank, 0, nothing, Mid)
    else
        return MPIRef(space.comm, space.rank, sizeof(x), poolset(x; device, kwargs...), Mid)
    end
end

const DEADLOCK_DETECT = TaskLocalValue{Bool}(()->true)

const DEADLOCK_WARN_PERIOD = TaskLocalValue{Float64}(()->parse(Float64, get(ENV, "JULIA_DAGGER_MPI_WARN_PERIOD", "10.0")))
const DEADLOCK_TIMEOUT_PERIOD = TaskLocalValue{Float64}(()->parse(Float64, get(ENV, "JULIA_DAGGER_MPI_TIMEOUT_PERIOD", "120.0")))
# Off by default: a full stacktrace buries the one-line diagnosis (which call
# site is waiting) in noise. Opt in with JULIA_DAGGER_MPI_WARN_BACKTRACE=1 when
# that call site itself is the thing in question.
const DEADLOCK_WARN_BACKTRACE = TaskLocalValue{Bool}(()->parse(Bool, get(ENV, "JULIA_DAGGER_MPI_WARN_BACKTRACE", "0")))

# Monotonic count of cross-rank operations this rank has *completed*: every
# finished `Isend`/`Irecv` request and every broadcast payload the relay hands
# to a slot. Only the volume matters, never the value, so relaxed increments
# from any thread are fine.
#
# This is what lets a wait tell "the job is moving and I am behind a peer" from
# "nothing is moving anywhere". A per-wait stopwatch cannot: how long one rank
# waits for another is bounded by the peer's *backlog*, not by any property of
# the wait itself, and datadeps deliberately lets that backlog grow (a region's
# tasks are submitted in one burst, so a non-owner can reach a task's metadata
# wait long before the owner starts it). Add a first-call JIT of the task body
# -- minutes, for a wide `@stencil` -- and a single legitimate wait runs well
# past any fixed timeout. Timing that wait alone reports a deadlock that is not
# there; timing it against this counter reports one only when the rank has
# genuinely stopped doing cross-rank work.
const MPI_PROGRESS = Threads.Atomic{UInt64}(0)
@inline note_mpi_progress!() = (Threads.atomic_add!(MPI_PROGRESS, UInt64(1)); nothing)

"""
    DeadlockTimer()

The stopwatch one cross-rank wait carries, rebuilt (not mutated) on each poll so
it stays isbits and costs no allocation on the wait loops.

`warn_period` is the live threshold and goes to `typemax` once this wait has
warned, so it warns at most once; `base_warn` is the value to restore when the
clock is reset. `last_progress` is the `MPI_PROGRESS` reading this wait was last
judged against. See `mpi_deadlock_detect`.
"""
struct DeadlockTimer
    detect::Bool
    time_start::UInt64
    warn_period::UInt64
    base_warn::UInt64
    timeout_period::UInt64
    last_progress::UInt64
end
function DeadlockTimer()
    warn_period = round(UInt64, DEADLOCK_WARN_PERIOD[] * 1e9)
    return DeadlockTimer(DEADLOCK_DETECT[], time_ns(), warn_period, warn_period,
                         round(UInt64, DEADLOCK_TIMEOUT_PERIOD[] * 1e9),
                         MPI_PROGRESS[])
end
# A present key with `nothing` denotes an active receiver with no competitors.
# Allocate an event only when a second receiver actually needs to wait.
const RECV_WAITING = LockedObject(Dict{Tuple{MPI.Comm, Int, Int}, Union{Base.Event,Nothing}}())

function acquire_recv!(key::Tuple{MPI.Comm,Int,Int})
    while true
        local other_event
        @lock RECV_WAITING begin
            waiting = Dagger.payload(RECV_WAITING)
            if !haskey(waiting, key)
                waiting[key] = nothing
                return
            end
            other_event = waiting[key]
            if other_event === nothing
                other_event = Base.Event()
                waiting[key] = other_event
            end
        end
        wait(other_event::Base.Event)
    end
end

function release_recv!(key::Tuple{MPI.Comm,Int,Int})
    @lock RECV_WAITING begin
        other_event = pop!(Dagger.payload(RECV_WAITING), key)
        other_event === nothing || notify(other_event)
    end
    return
end

# Envelope for the out-of-place raw-bytes MPI path: serialize a small
# descriptor, then send contiguous bitstype buffers. Types register via
# Dagger's inplace_mpi_parts / inplace_mpi_alloc / inplace_mpi_build (same style
# as move_rewrap_parts / move_rewrap_build). Those generics are declared in core
# Dagger so container-specific methods can live in the extension owning the
# container (e.g. `SparseMatrixCSC` in MPISparseExt).
struct InplaceInfo
    type::DataType
    header  # Any MPI-serializable reconstruction metadata
end

# DenseArray: single contiguous buffer + shape header
function Dagger.inplace_mpi_parts(A::DenseArray)
    isbitstype(eltype(A)) || return nothing
    return ((A,), size(A))
end
function Dagger.inplace_mpi_alloc(::Type{T}, shape::Tuple) where {T<:DenseArray}
    # Always materialize on the host: the sender host-stages device arrays,
    # and callers convert to the destination space's native storage
    return (Array{eltype(T)}(undef, shape),)
end
Dagger.inplace_mpi_build(::Type{<:DenseArray}, (A,), ::Tuple) = A

function supports_inplace_mpi(value)
    if value isa DenseArray && isbitstype(eltype(value))
        return true
    else
        return false
    end
end

# Whether the loaded MPI library is known to support device buffers of `kind`
# (GPU extensions cannot depend on MPI, so they query through this).
# `mpi_device_direct`/`mpi_device_sync`/`mpi_remap_space` defaults live in core
# Dagger (src/gpu.jl); this method refines `mpi_library_gpu_aware`.
function mpi_library_gpu_aware(kind::Symbol)
    MPI.Initialized() || return false
    kind === :CUDA && return MPI.has_cuda()
    kind === :ROC && return MPI.has_rocm()
    # MPI.jl has no has_ze/has_level_zero; Intel GPU-aware MPI is opt-in via
    # Intel MPI + I_MPI_OFFLOAD, or JULIA_MPI_HAS_ONEAPI / DAGGER_MPI_GPU_DIRECT
    if kind === :oneAPI
        env = get(ENV, "JULIA_MPI_HAS_ONEAPI", "")
        !isempty(env) && return something(tryparse(Bool, env), false)
        offload = get(ENV, "I_MPI_OFFLOAD", "")
        isempty(offload) && return false
        something(tryparse(Int, offload), 0) <= 0 && return false
        impl = try
            MPI.MPI_LIBRARY
        catch
            ""
        end
        return occursin(r"(?i)intel|impi", String(impl))
    end
    return false
end

### Same-node device IPC fast path (MPI handle transport)
# Eligibility and export/import live in gpu.jl / GPU extensions. Here we only
# exchange the small handle over MPI P2P and wait for an ack so the sender can
# release its staging allocation. Host staging for the non-IPC path uses
# STAGE_POOLS / stage_* from gpu.jl.

# The sender keeps its staging alive until the receiver acknowledges the
# device-to-device copy; the ack wait polls via Improbe+yield (recv_yield)
function mpi_ipc_send(value, comm, dest, tag)
    info, token = ipc_export(value)
    try
        send_yield(info, comm, dest, tag)
        ack = recv_yield(comm, dest, tag)
        @assert ack === true "Unexpected IPC ack: $(repr(ack))"
    finally
        ipc_release!(token)
    end
    return
end
function mpi_ipc_recv!(dest, comm, src, tag)
    info = recv_yield(comm, src, tag)
    ipc_copyto!(dest, info)
    send_yield(true, comm, src, tag)
    return dest
end
function mpi_ipc_recv_materialize(comm, src, tag)
    info = recv_yield(comm, src, tag)
    value = ipc_materialize(info)
    send_yield(true, comm, src, tag)
    return value
end
function recv_yield!(buffer, comm, src, tag)
    rank = MPI.Comm_rank(comm)
    #Core.println("buffer recv: $buffer, type of buffer: $(typeof(buffer)), is in place? $(supports_inplace_mpi(buffer))")
    if !supports_inplace_mpi(buffer)
        return recv_yield(comm, src, tag), false
    end
    #Core.println("[rank $(MPI.Comm_rank(comm))][tag $tag] Starting recv! from [$src]")

    key = (comm, Int(src), Int(tag))
    acquire_recv!(key)
    try
        return recv_yield_inplace!(buffer, comm, rank, src, tag), true
    finally
        release_recv!(key)
    end
end

function recv_yield(comm, src, tag)
    rank = MPI.Comm_rank(comm)
    #Core.println("[rank $(MPI.Comm_rank(comm))][tag $tag] Starting recv from [$src]")

    key = (comm, Int(src), Int(tag))
    acquire_recv!(key)
    try
        value = recv_yield_serialized(comm, rank, src, tag)
        if value isa InplaceInfo
            return recv_yield_inplace(value, comm, rank, src, tag)
        end
        return value
    finally
        release_recv!(key)
    end
end

# Device-resident dense array: receive directly when the MPI library is
# GPU-aware, otherwise through a host staging buffer
function recv_yield_inplace!(array::DenseArray, comm, my_rank, their_rank, tag)
    if mpi_device_direct(array)
        mpi_device_sync(array)
        return _recv_yield_inplace_raw!(array, comm, my_rank, their_rank, tag)
    end
    kind = gpu_memory_kind(array)
    buf = stage_acquire!(kind, sizeof(array))
    GC.@preserve buf begin
        host = unsafe_wrap(Array, Ptr{eltype(array)}(pointer(buf)), size(array))
        _recv_yield_inplace_raw!(host, comm, my_rank, their_rank, tag)
        with_context!(memory_space(array))
        copyto!(array, host)
    end
    # The upload runs on this task's stream; consumers run on other
    # tasks/streams, so it must be visible before we hand the buffer over
    mpi_device_sync(array)
    stage_release!(kind, buf)
    return array
end
recv_yield_inplace!(array::Array, comm, my_rank, their_rank, tag) =
    _recv_yield_inplace_raw!(array, comm, my_rank, their_rank, tag)
function _recv_yield_inplace_raw!(array, comm, my_rank, their_rank, tag)
    timer = DeadlockTimer()

    while true
        (got, msg, stat) = MPI.Improbe(their_rank, tag, comm, MPI.Status)
        if got
            if MPI.Get_error(stat) != MPI.SUCCESS
                error("recv_yield failed with error $(MPI.Get_error(stat))")
            end
            count = MPI.Get_count(stat, UInt8)
            @assert count == sizeof(array) "recv_yield_inplace: expected $(sizeof(array)) bytes, got $count"
            buf = MPI.Buffer(array)
            req = MPI.Imrecv!(buf, msg)
            __wait_for_request(req, comm, my_rank, their_rank, tag, "recv_yield", "recv")
            return array
        end
        timer = mpi_deadlock_detect(timer, my_rank, tag, "recv", their_rank)
        yield()
    end
end

function recv_yield_inplace(_value::InplaceInfo, comm, my_rank, their_rank, tag)
    T = _value.type
    parts = inplace_mpi_alloc(T, _value.header)
    parts = map(p -> recv_yield_inplace!(p, comm, my_rank, their_rank, tag), parts)
    return inplace_mpi_build(T, parts, _value.header)
end

function recv_yield_serialized(comm, my_rank, their_rank, tag)
    timer = DeadlockTimer()

    while true
        (got, msg, stat) = MPI.Improbe(their_rank, tag, comm, MPI.Status)
        if got
            if MPI.Get_error(stat) != MPI.SUCCESS
                error("recv_yield failed with error $(MPI.Get_error(stat))")
            end
            count = MPI.Get_count(stat, UInt8)
            buf = Array{UInt8}(undef, count)
            req = MPI.Imrecv!(MPI.Buffer(buf), msg)
            __wait_for_request(req, comm, my_rank, their_rank, tag, "recv_yield", "recv")
            return MPI.deserialize(buf)
        end
        timer = mpi_deadlock_detect(timer, my_rank, tag, "recv", their_rank)
        yield()
    end
end

send_yield!(value, comm, dest, tag) =
    _send_yield(value, comm, dest, tag; inplace=true)
send_yield(value, comm, dest, tag) =
    _send_yield(value, comm, dest, tag; inplace=false)
function _send_yield(value, comm, dest, tag; inplace::Bool)
    rank = MPI.Comm_rank(comm)

    #Core.println("[rank $(MPI.Comm_rank(comm))][tag $tag] Starting send to [$dest]: $(typeof(value)), is support inplace? $(supports_inplace_mpi(value))")
    if inplace && supports_inplace_mpi(value)
        if value isa Array
            send_yield_inplace(value, comm, rank, dest, tag)
        elseif mpi_device_direct(value)
            # GPU-aware MPI: hand the device buffer to MPI directly
            mpi_device_sync(value)
            send_yield_inplace(value, comm, rank, dest, tag)
        else
            # Device-resident dense array: stage through a pooled (pinned)
            # host buffer so the raw-bytes protocol works without GPU-aware
            # MPI. Producers may have enqueued work on other streams, so sync
            # before reading.
            mpi_device_sync(value)
            host, buf, kind = stage_to_host!(value)
            GC.@preserve buf begin
                send_yield_inplace(host, comm, rank, dest, tag)
            end
            stage_release!(kind, buf)
        end
    else
        send_yield_serialized(value, comm, rank, dest, tag)
    end
end

function send_yield_inplace(value, comm, my_rank, their_rank, tag)
    @opcounter :send_yield_inplace
    req = MPI.Isend(value, comm; dest=their_rank, tag)
    __wait_for_request(req, comm, my_rank, their_rank, tag, "send_yield", "send")
end

# Send one contiguous part, staging device arrays through host when needed
function send_yield_inplace_part(part, comm, my_rank, their_rank, tag)
    if part isa Array
        send_yield_inplace(part, comm, my_rank, their_rank, tag)
    elseif part isa DenseArray
        # Device-resident dense array: send bytes directly under GPU-aware
        # MPI, or host-staged otherwise (receiver materializes on the host)
        mpi_device_sync(part)
        if mpi_device_direct(part)
            send_yield_inplace(part, comm, my_rank, their_rank, tag)
        else
            host, buf, kind = stage_to_host!(part)
            GC.@preserve buf begin
                send_yield_inplace(host, comm, my_rank, their_rank, tag)
            end
            stage_release!(kind, buf)
        end
    else
        send_yield_inplace(part, comm, my_rank, their_rank, tag)
    end
end

function send_yield_serialized(value, comm, my_rank, their_rank, tag)
    @opcounter :send_yield_serialized
    parts_hdr = inplace_mpi_parts(value)
    if parts_hdr !== nothing
        parts, header = parts_hdr
        send_yield_serialized(InplaceInfo(typeof(value), header), comm, my_rank, their_rank, tag)
        for part in parts
            send_yield_inplace_part(part, comm, my_rank, their_rank, tag)
        end
    else
        req = MPI.isend(value, comm; dest=their_rank, tag)
        __wait_for_request(req, comm, my_rank, their_rank, tag, "send_yield", "send")
    end
end

function __wait_for_request(req, comm, my_rank, their_rank, tag, fn::String, kind::String)
    timer = DeadlockTimer()
    while true
        finish, status = MPI.Test(req, MPI.Status)
        if finish
            if MPI.Get_error(status) != MPI.SUCCESS
                error("$fn failed with error $(MPI.Get_error(status))")
            end
            # Every completed request is this rank's proof of life for the
            # waits running concurrently with it (see `MPI_PROGRESS`).
            note_mpi_progress!()
            return
        end
        timer = mpi_deadlock_detect(timer, my_rank, tag, kind, their_rank)
        yield()
    end
end

function bcast_send_yield(value, comm, root, tag)
    @opcounter :bcast_send_yield
    sz = MPI.Comm_size(comm)
    rank = MPI.Comm_rank(comm)
    for other_rank in 0:(sz-1)
        rank == other_rank && continue
        send_yield(value, comm, other_rank, tag)
    end
end

# Binomial-tree broadcast built from the tagged nonblocking P2P primitives
# (never an MPI collective). Every rank calls this at the same logical point:
# the root passes the value, the others receive from their tree parent,
# forward to their tree children, and return the received value. The tree is
# a pure function of (rank, root, comm size), hence rank-uniform; O(log P)
# latency instead of the root serially sending to P-1 peers.
function bcast_yield(comm, root::Integer, tag, value=nothing)
    @opcounter :bcast_yield
    sz = MPI.Comm_size(comm)
    sz == 1 && return value
    rank = MPI.Comm_rank(comm)
    vrank = mod(rank - root, sz)
    mask = 1
    while mask < sz
        if vrank & mask != 0
            value = recv_yield(comm, mod(rank - mask, sz), tag)
            break
        end
        mask <<= 1
    end
    mask >>= 1
    while mask > 0
        if vrank + mask < sz
            send_yield(value, comm, mod(rank + mask, sz), tag)
        end
        mask >>= 1
    end
    return value
end

# Escalate a wait only while this rank is doing no cross-rank work at all.
#
# Waiting a long time is not evidence of a deadlock (see `MPI_PROGRESS`): it is
# the normal cost of being behind a peer. What *is* evidence is waiting while
# nothing else on this rank completes, so every poll that sees the counter move
# restarts the clock, and the warn/timeout thresholds then measure a stall
# rather than a wait. A real cycle still trips them, just once the work that
# does not depend on it has drained.
function mpi_deadlock_detect(timer::DeadlockTimer, rank, tag, kind, srcdest)
    # A wait on a task's result ends in that task's error when its owner failed
    POISON_REF[] === nothing || mpi_check_poison()
    timer.detect || return timer
    progress = MPI_PROGRESS[]
    if progress != timer.last_progress
        return DeadlockTimer(true, time_ns(), timer.base_warn, timer.base_warn,
                             timer.timeout_period, progress)
    end
    time_elapsed = (time_ns() - timer.time_start)
    if time_elapsed > timer.warn_period
        # A hang here is a wait cycle across ranks, so which call site is waiting
        # (and on whose behalf) is the whole diagnosis; a bare tag is not enough.
        # The backtrace that pins down the call site is off by default, though --
        # see DEADLOCK_WARN_BACKTRACE.
        if DEADLOCK_WARN_BACKTRACE[]
            @warn "[rank $rank][tag $tag] Hit probable hang on $kind (dest: $srcdest)" stacktrace=sprint(Base.show_backtrace, stacktrace())
        else
            @warn "[rank $rank][tag $tag] Hit probable hang on $kind (dest: $srcdest)"
        end
        return DeadlockTimer(true, timer.time_start, typemax(UInt64), timer.base_warn,
                             timer.timeout_period, progress)
    end
    if time_elapsed > timer.timeout_period
        error("[rank $rank][tag $tag] Hit hang on $kind (dest: $srcdest)")
    end
    return timer
end

# ---------------------------------------------------------------------------
# Dispatch-decoupled binomial-tree broadcast for per-task metadata
#
# `bcast_yield` (above) is a correct O(log P) tree, but when it runs INSIDE a
# task's syncdep-gated `execute!` coroutine an intermediate rank cannot forward
# a broadcast until the scheduler dispatches that same task on it. With many
# per-task metadata broadcasts overlapping (4 ranks × many chunks) that
# "forward only once I'm dispatched" gate closes a cross-rank wait cycle — the
# hang seen on Julia 1.10/1.11.
#
# A non-owner needs none of the task's data to relay/consume the tiny status/
# type payload, so drive the tree from an always-running per-rank relay that
# forwards ON MESSAGE ARRIVAL (independent of task dispatch) over a dedicated
# duplicated `bcast_comm`, delivering payloads to per-tag slots. The root just
# fires to its children and returns; non-roots yield-wait their slot. The wait
# graph then reduces to the acyclic datadeps DAG (receiver → owner compute →
# owner syncdeps), so it cannot deadlock, while keeping the O(log P) tree.
# Only the fixed-size `execute!` metadata uses this path; large value
# broadcasts (poolget/collect/fetch) keep the in-task tree at their sequential,
# non-overlapping points.

# Binomial-tree children of `rank` in the tree rooted at `root` over `sz` ranks
# (identical virtual-rank math to `bcast_yield`, so relay and root agree on the
# topology).
function bcast_tree_children(rank::Int, root::Int, sz::Int)
    vrank = mod(rank - root, sz)
    mask = 1
    while mask < sz
        (vrank & mask != 0) && break
        mask <<= 1
    end
    mask >>= 1
    children = Int[]
    while mask > 0
        if vrank + mask < sz
            push!(children, mod(rank + mask, sz))
        end
        mask >>= 1
    end
    return children
end

# Delivered broadcast payloads for one (root, tag) pair, in arrival order.
#
# N.B. A FIFO, not a one-shot promise, because a tag does NOT identify a single
# broadcast. `to_tag()` returns the planning task's thunk id, so every
# `move_rewrap` header broadcast issued while generating that task's slots
# shares one tag -- including one per level of a nested wrapper, and one per
# argument. A one-shot slot keeps only the last of those: the earlier payload is
# overwritten before its consumer reads it, the consumer then takes the wrong
# value and the next consumer waits forever on a delivery that already happened.
# That is a silent hang, since nothing downstream of the relay is covered by
# `mpi_deadlock_detect`.
#
# Queue order matches sender intent: MPI's non-overtaking guarantee delivers
# same-(source, tag) messages in send order, each relay forwards in that same
# order, and SPMD planning issues and consumes them in one rank-uniform order.
# Keying on the root as well as the tag keeps two roots that happen to share a
# tag from interleaving into a single queue, where no ordering rule applies.
mutable struct BcastSlot
    values::Vector{Any}
    cond::Union{Threads.Condition,Nothing}
    waiters::Int
    BcastSlot() = new(Any[], nothing, 0)
end

mutable struct BcastState
    bcast_comm::MPI.Comm
    slots::Dict{Tuple{Int,UInt32},BcastSlot}
    # Guards `slots`; each slot's condition shares this lock but has its own
    # wait queue. A delivery must only wake that (root, tag)'s consumers, not
    # every task blocked on an unrelated broadcast in the region.
    cond::Threads.Condition
    running::Threads.Atomic{Bool}
    relay::Union{Task,Nothing}
end

# Keyed by the acceleration comm (what `execute!`/`bcast_meta_yield` see). The
# relay owns the duplicated `bcast_comm`, so it can `Improbe(ANY_SOURCE,
# ANY_TAG)` without colliding with main-comm P2P transfers or the in-task
# `bcast_yield` tree.
const BCAST_STATES = LockedObject(Dict{MPI.Comm,BcastState}())

bcast_state_for(comm::MPI.Comm) =
    lock(BCAST_STATES) do states
        states[comm]
    end

bcast_serialize(x) = (io = IOBuffer(); Serialization.serialize(io, x); take!(io))

function bcast_slot!(state::BcastState, key::Tuple{Int,UInt32})
    slot = get(state.slots, key, nothing)
    if slot === nothing
        slot = BcastSlot()
        state.slots[key] = slot
    end
    return slot
end

function bcast_deliver!(state::BcastState, root::Int, tag::UInt32, value)
    # `@lock`, not `lock(...) do`: the `do` block is a closure over `state`,
    # `root`, `tag` and `value`, which boxes them and allocates on a path the
    # relay runs for every delivered payload.
    @lock state.cond begin
        slot = bcast_slot!(state, (root, tag))
        push!(slot.values, value)
        cond = slot.cond
        cond === nothing || notify(cond)
    end
    # A delivered payload is cross-rank progress even when it is not the one a
    # given consumer is waiting for (see `MPI_PROGRESS`).
    note_mpi_progress!()
    return
end

# Wake every consumer so each can re-check its own elapsed time. Called by the
# relay while it is idle, which makes the relay the heartbeat that drives
# deadlock detection -- no `Timer` involved, and so nothing that depends on a
# thread reaching the scheduler's idle loop to service libuv.
function bcast_heartbeat!(state::BcastState)
    @lock state.cond begin
        for slot in values(state.slots)
            cond = slot.cond
            cond === nothing || notify(cond)
        end
    end
    return
end

function bcast_slot_wait(state::BcastState, root::Int, tag::UInt32)
    key = (root, tag)
    # Enqueueing under the same lock means relay-before-consumer and
    # consumer-before-relay both work: a payload that arrived first is simply
    # already queued when we first look.
    #
    # The wait is routed through `mpi_deadlock_detect` like every other
    # cross-rank wait in this extension. Before, this was a bare `wait` on a
    # one-shot `Event`, so a delivery that was lost (see `BcastSlot`) stalled
    # here forever with nothing to report -- a CI job exhausting its timeout
    # with no error to point at. Re-checks are driven by `bcast_heartbeat!`
    # rather than by polling, so a blocked consumer costs no CPU.
    timer = DeadlockTimer()
    rank = MPI.Comm_rank(state.bcast_comm)
    # `@lock`, not `lock(...) do`: the loop closes over enough of the enclosing
    # frame (`key`, the deadlock-timer state, `rank`) that the closure boxes
    # them, and `timer` -- reassigned across iterations and captured -- becomes
    # a heap `Box`. Inlining the body keeps all of it on the stack; the `return`
    # below still releases the lock, via `@lock`'s `finally`.
    @lock state.cond begin
        slot = bcast_slot!(state, key)
        slot.waiters += 1
        try
            while true
                if !isempty(slot.values)
                    return popfirst!(slot.values)
                end
                # A heartbeat/delivery may have already woken this consumer
                # when teardown runs, leaving it outside the notified queues.
                state.running[] || throw(ConcurrencyViolationError("MPI broadcast relay stopped while a consumer was waiting"))
                timer = mpi_deadlock_detect(timer, rank, tag, "bcast_meta delivery", root)
                # Already-delivered payloads need no condition allocation.
                if slot.cond === nothing
                    slot.cond = Threads.Condition(state.cond.lock)
                end
                wait(slot.cond::Threads.Condition)
            end
        finally
            slot.waiters -= 1
            # A woken consumer may not have reacquired the lock yet. Retain
            # its slot even if another consumer drains the last payload, or
            # the next delivery would notify a different condition.
            isempty(slot.values) && slot.waiters == 0 && delete!(state.slots, key)
        end
    end
end

# How many consecutive empty probes to spin through before the relay starts
# sleeping between them, and how long it then sleeps.
#
# A bare `Improbe`/`yield()` loop never blocks, so it keeps a whole OS thread at
# 100% forever: a profile of a 4-rank run spent 107 of one thread's 127 samples
# inside `MPI_Improbe`. With one relay per rank that burns one core per rank,
# which is survivable on a workstation but not on a 4-vCPU CI runner hosting 4
# ranks -- there the relays alone claim the entire machine and the threads doing
# real work are left to fight over what is left. The cost scales with rank
# count, so it hits the 4-rank job far harder than the 2-rank one.
#
# Broadcast traffic is bursty -- planning issues them in clusters -- so spin hot
# first and only back off once the burst is clearly over. That keeps the added
# latency off the messages inside a burst and pays it at most once, on the first
# message of the next one.
const BCAST_RELAY_SPIN_ITERS = 4096
const BCAST_RELAY_IDLE_SLEEP = 1e-4
# Heartbeat cadence once idle, counted in backoff iterations: at ~150us apiece
# this wakes blocked consumers roughly every 150ms, which is fine granularity
# for a 10s warn / 120s error timer and costs nothing when nobody is waiting.
const BCAST_RELAY_HEARTBEAT_ITERS = 1000

# Always-running per-rank progress engine: receive a broadcast on `bcast_comm`,
# forward the raw bytes to this rank's tree children, then deliver the payload.
# Forwarding is NOT gated by datadeps task dispatch — that is what breaks the
# forwarder wait-cycle.
function bcast_relay_loop(state::BcastState, spin_iters::Int=BCAST_RELAY_SPIN_ITERS)
    comm = state.bcast_comm
    rank = MPI.Comm_rank(comm)
    sz = MPI.Comm_size(comm)
    idle = 0
    # Backing off means blocking the OS thread, which only gives time back to
    # anyone else if this rank has another thread to run them on. On a
    # single-threaded rank it would instead starve the very tasks the relay
    # exists to serve, so there we keep the pure `yield()` loop.
    may_backoff = Threads.nthreads() > 1
    while state.running[]
        try
            MPI.Finalized() && break
            got, msg, stat = MPI.Improbe(MPI.ANY_SOURCE, MPI.ANY_TAG, comm, MPI.Status)
            if !got
                idle += 1
                if idle <= spin_iters || !may_backoff
                    yield()
                else
                    # N.B. `Libc.systemsleep`, not `sleep`: `sleep` parks the
                    # task on a libuv timer, which only fires when some thread
                    # reaches the scheduler's idle loop. A rank whose other
                    # thread is inside a blocking `ccall` has no such thread, so
                    # the relay could stay asleep exactly when it is needed
                    # most. Sleeping the thread outright cannot be starved that
                    # way, and 100us is short enough that the GC-unsafe window
                    # it opens is irrelevant.
                    Libc.systemsleep(BCAST_RELAY_IDLE_SLEEP)
                    yield()
                end
                # Nothing is arriving, which is exactly when a stalled consumer
                # needs its deadlock timer re-checked -- and the relay is the
                # one thing guaranteed to still be running to do it.
                if idle % BCAST_RELAY_HEARTBEAT_ITERS == 0
                    bcast_heartbeat!(state)
                end
                continue
            end
            idle = 0
            src = MPI.Get_source(stat)
            tag = UInt32(MPI.Get_tag(stat))
            count = MPI.Get_count(stat, UInt8)
            buf = Array{UInt8}(undef, count)
            req = MPI.Imrecv!(MPI.Buffer(buf), msg)
            __wait_for_request(req, comm, rank, src, tag, "bcast_relay", "recv")
            root, value = Serialization.deserialize(IOBuffer(buf))
            for child in bcast_tree_children(rank, Int(root), sz)
                sreq = MPI.Isend(buf, comm; dest=child, tag=tag)
                __wait_for_request(sreq, comm, rank, child, tag, "bcast_relay", "send")
            end
            bcast_deliver!(state, Int(root), tag, value)
        catch err
            # Comm torn down (disable/finalize) races the loop: stop quietly.
            # A genuine mid-session fault surfaces via errormonitor.
            (state.running[] && !MPI.Finalized()) || break
            rethrow(err)
        end
    end
    return
end

function start_bcast_relay!(accel_comm::MPI.Comm)
    bcast_comm = MPI.Comm_dup(accel_comm)
    state = BcastState(bcast_comm, Dict{Tuple{Int,UInt32},BcastSlot}(),
                       Threads.Condition(), Threads.Atomic{Bool}(true), nothing)
    lock(BCAST_STATES) do states
        states[accel_comm] = state
    end
    mode = get(ENV, "JULIA_DAGGER_MPI_RELAY", "auto")
    nthr = Threads.nthreads(:default)
    # A migratable relay that spins on `yield()` wakes another thread with every call (the task goes back to the shared
    # queue), which keeps most of a rank's threads out of sleep: a cross-rank dependency cost 2.2-2.9 ms against 0.4 ms,
    # and on the cluster the rank burned 181-216 CPU s per qr region against 44, with the kernels 6-14 % slower. A migratable
    # relay therefore does not spin (it sleeps 100 us between probes at once); one that stays on the driver's thread keeps the spin,
    # because it shares that thread and must yield to the tasks there. `JULIA_DAGGER_MPI_RELAY_SPINS` forces a count.
    migratable = !(mode == "main" || (mode == "auto" && nthr < 4))
    spin_iters = parse(Int, get(ENV, "JULIA_DAGGER_MPI_RELAY_SPINS", string(migratable ? 0 : BCAST_RELAY_SPIN_ITERS)))
    t = Task(() -> bcast_relay_loop(state, spin_iters))
    # N.B. `sticky = false` alone is not enough: a `Task` made on a thread-bound task (the driver, once Distributed
    # has used `@async`) starts on its creator's thread. The relay would then share the driver's thread, and a driver
    # parked in a blocking MPI call (an `MPI.Allgather` or `Barrier` in user code) would stop it from forwarding the
    # broadcasts the other ranks wait for: a cross-rank cycle (it hung the full MPI suite across two nodes, where
    # those collectives take longer than in shared memory). Lesson 98 made the lend service migratable and left this
    # task bound.
    # `auto`: migratable from 4 default threads on, the old placement (starts on the creator's thread) below. The relay is a
    # polling loop that keeps a thread busy; migratable on a 2-thread rank it competes with the tasks for the only free thread
    # and hung the delegation test 4 ranks x 2 threads (cluster: 3 of 3 runs; MPICH laptop: 1 of 5, against 0 of 5 and 0 of 4 for the
    # old placement), pinned to the last thread was worse (3 of 5 hung). From 4 threads on it passes (4 and 8 threads, 2 nodes).
    # `JULIA_DAGGER_MPI_RELAY=main|migratable|last` forces a placement.
    if mode == "main" || (mode == "auto" && nthr < 4)
        t.sticky = false
    elseif mode == "last"
        Dagger.set_task_tid!(t, nthr)
    elseif mode == "interactive" && Threads.nthreads(:interactive) > 0
        # A thread of the interactive pool (`-t N,1`) is not one of the threads the scheduler places tasks on
        t.sticky = false
        Base.Threads._spawn_set_thrpool(t, :interactive)
    else
        Dagger.set_task_migratable!(t)
    end
    schedule(t)
    Dagger.Sch.errormonitor_tracked("mpi_bcast_relay", t)
    state.relay = t
    # `start_bcast_relay!` runs strictly after `MPI.Init`, so this hook is
    # registered after MPI.jl's Finalize hook and (atexit is LIFO) runs before
    # it — the relay is stopped and joined before MPI shuts down, otherwise a
    # relay mid-`Improbe` on another thread races Finalize and MPICH aborts.
    atexit(() -> stop_bcast_relay!(accel_comm))
    return state
end

function stop_bcast_relay!(accel_comm::MPI.Comm)
    state = lock(BCAST_STATES) do states
        s = get(states, accel_comm, nothing)
        s === nothing || delete!(states, accel_comm)
        s
    end
    state === nothing && return nothing
    state.running[] = false
    # Join so no in-flight probe/recv can outlive the comm; a relay that died
    # to a teardown race already reported via errormonitor, so swallow it here.
    relay = state.relay
    if relay !== nothing && relay !== current_task()
        try
            wait(relay)
        catch
        end
    end
    # The relay is the heartbeat that lets a blocked consumer re-check its
    # deadlock timer, so once it is gone nothing would ever wake a consumer
    # still waiting on a payload that is now never coming. Fail them instead of
    # letting teardown hang.
    @lock state.cond begin
        for slot in values(state.slots)
            cond = slot.cond
            if cond !== nothing
                notify(cond,
                       ConcurrencyViolationError("MPI broadcast relay stopped while a consumer was waiting");
                       error=true)
            end
        end
    end
    return nothing
end

# Dispatch-decoupled broadcast used by `execute!` for per-task metadata. The
# root fires `(root, value)` to its tree children on `bcast_comm` and returns;
# every other rank waits for the relay to deliver its copy.
function bcast_meta_yield(comm::MPI.Comm, root::Integer, tag, value=nothing)
    sz = MPI.Comm_size(comm)
    sz == 1 && return value
    rank = MPI.Comm_rank(comm)
    state = bcast_state_for(comm)
    utag = UInt32(tag)
    if rank == root
        buf = bcast_serialize((Int(root), value))
        bcomm = state.bcast_comm
        for child in bcast_tree_children(rank, Int(root), sz)
            req = MPI.Isend(buf, bcomm; dest=child, tag=utag)
            __wait_for_request(req, bcomm, rank, child, utag, "bcast_meta", "send")
        end
        return value
    else
        return bcast_slot_wait(state, Int(root), utag)
    end
end

# --- Failure-only task status ---------------------------------------------------
#
# `execute!` of a task that may throw makes the owner broadcast `:ok`/`:error` and
# every other rank wait for it, so every rank is coupled to every task. For the
# tasks `elide_task!` handles (see "Owner elision") the status is instead sent
# *only on failure*: ranks never wait for success, and a rank that later needs the
# task's data -- an argument move or a fetch -- stops waiting when the failure
# arrives. The failure is the `(:error, ex)` payload of the owner's broadcast on
# the task's tag, which the relay keeps in the task's (root, tag) slot; the data
# the task produced carries that tag in its ref id (`MPIRefID.tid`), so a wait on
# a `MPIRef` can look the failure up. Waits install the ref they are on behalf of
# in `POISON_REF`, and every polling wait already goes through
# `mpi_deadlock_detect`, which checks it.

const POISON_REF = ScopedValue{Union{MPIRef,Nothing}}(nothing)

function mpi_check_poison()
    ref = POISON_REF[]::MPIRef
    ref.id.generic && return
    state = lock(BCAST_STATES) do states
        get(states, ref.comm, nothing)
    end
    state === nothing && return
    err = nothing
    @lock state.cond begin
        slot = get(state.slots, (ref.rank, UInt32(mpi_tag_of(ref.id.tid))), nothing)
        if slot !== nothing && !isempty(slot.values)
            msg = slot.values[1]
            msg isa Tuple && first(msg) === :error && (err = msg[2])
        end
    end
    err === nothing || throw(err)
    return
end

# Run `f` (a wait on data of `ref`'s task) so that it ends in that task's error
mpi_poisonable(f, ref::MPIRef) =
    Dagger.ELIDE_FOREIGN_TASKS[] ? with(f, POISON_REF => ref) : f()

WeakChunk(c::Chunk{T,H}) where {T,H<:MPIRef} = WeakChunk(c.handle.rank, c.handle.id.id, WeakRef(c), T)

# The generic id a fetch takes (and so the tag of its broadcast) comes from the counter of the communicator the
# chunk lives in, wherever the fetch is called from: a fetch of a result of a group graph outside its `with_group`
# block must not take an id from the world's counter (the ranks outside the group do not take one), and a fetch
# of a world chunk inside a group block must not take one from the group's.
function mpi_fetch_tag(comm::MPI.Comm)
    a = Dagger.current_acceleration()
    a isa MPIAcceleration && a.comm == comm && return to_tag()
    accel = comm == MPI.COMM_WORLD ? MPIAcceleration(comm) : mpi_group_acceleration(comm)
    return Dagger.with_acceleration(to_tag, accel)
end

function MemPool.poolget(ref::MPIRef; uniform::Bool=uniform_execution())
    @assert uniform || ref.rank == MPI.Comm_rank(ref.comm) "MPIRef rank mismatch: $(ref.rank) != $(MPI.Comm_rank(ref.comm))"
    # A communicator of size one has nobody to broadcast to, and the tag a broadcast takes
    # would be a generic id that only this rank consumes
    uniform && MPI.Comm_size(ref.comm) == 1 && return poolget(ref.innerRef)
    if uniform
        tag = mpi_fetch_tag(ref.comm)
        if ref.rank == MPI.Comm_rank(ref.comm)
            return bcast_yield(ref.comm, ref.rank, tag, poolget(ref.innerRef))
        else
            return mpi_poisonable(ref) do
                bcast_yield(ref.comm, ref.rank, tag)
            end
        end
    else
        return poolget(ref.innerRef)
    end
end
fetch_handle(ref::MPIRef; uniform::Bool=uniform_execution()) = poolget(ref; uniform)

function move!(dep_mod, to_space::MPIMemorySpace, from_space::MPIMemorySpace, to::Chunk, from::Chunk)
    @assert to.handle isa MPIRef && from.handle isa MPIRef "MPIRef expected"
    @assert to.handle.comm == from.handle.comm "MPIRef comm mismatch"
    @assert to.handle.rank == to_space.rank && from.handle.rank == from_space.rank "MPIRef rank mismatch"
    local_rank = MPI.Comm_rank(from.handle.comm)
    if to_space.rank == from_space.rank == local_rank
        move!(dep_mod, to_space.innerSpace, from_space.innerSpace, to, from)
    else
        # Prefer the copy task's own (uniform, unique) tag; fall back to the
        # source handle's tag outside of task context
        tag = Dagger.in_task() ? to_tag() : to_tag(from.handle)
        @dagdebug nothing :mpi "[$local_rank][$tag] Moving from  $(from_space.rank)  to  $(to_space.rank)\n"
        if dep_mod === identity
            # Below the crossover, handle+ack overhead makes host staging
            # competitive; each side checks its own (equal-sized) buffer
            local_nbytes = local_rank == from_space.rank ? from.handle.size :
                           local_rank == to_space.rank   ? to.handle.size : 0
            if ipc_type_eligible(chunktype(from)) &&
               ipc_eligible(from_space.innerSpace, to_space.innerSpace) &&
               local_nbytes >= IPC_MIN_BYTES[] &&
               same_node(current_acceleration(), from_space.rank, to_space.rank)
                # Same-node device-to-device: ship only an IPC handle
                if local_rank == from_space.rank
                    mpi_ipc_send(poolget(from.handle; uniform=false), to_space.comm, to_space.rank, tag)
                elseif local_rank == to_space.rank
                    mpi_ipc_recv!(poolget(to.handle; uniform=false), from_space.comm, from_space.rank, tag)
                end
            # Full copy: receive directly into the destination buffer when possible
            elseif local_rank == from_space.rank
                send_yield!(poolget(from.handle; uniform=false), to_space.comm, to_space.rank, tag)
            elseif local_rank == to_space.rank
                to_val = poolget(to.handle; uniform=false)
                val, inplace = recv_yield!(to_val, from_space.comm, from_space.rank, tag)
                if !inplace
                    # Dense payloads may arrive host-staged; materialize in
                    # dest storage so inner move! sees matching spaces
                    val = mpi_localize(to_space.innerSpace, val)
                    move!(dep_mod, to_space.innerSpace, from_space.innerSpace, to_val, val)
                end
            end
        else
            # Partial copy (e.g. UpperTriangular): the destination must only
            # update the dep_mod-selected region. Both sides compute the
            # modifier's memory spans from their own replicas (counts and
            # lengths are rank-uniform; addresses are local) and only the
            # selected region travels, packed through the staging pool.
            # Device arrays gather/scatter via multi_span_* (one KA launch).
            pack = true
            if local_rank == from_space.rank
                from_val = poolget(from.handle; uniform=false)
                if pack
                    ainfo = _with_default_acceleration() do
                        aliasing(from_val, dep_mod)
                    end
                    # Both sides compute this from identically-typed replicas,
                    # so the protocol choice stays rank-uniform
                    pack = !(ainfo isa NoAliasing || ainfo isa UnknownAliasing)
                end
                if pack
                    spans = memory_spans(ainfo)
                    len = sum(span_len, spans; init=UInt64(0))
                    kind = gpu_memory_kind(from_space.innerSpace)
                    stage_buf = stage_acquire!(kind, len)
                    copies = unsafe_wrap(Array, pointer(stage_buf), Int(len))
                    with_context!(from_space.innerSpace)
                    mpi_device_sync(from_space.innerSpace)
                    GC.@preserve stage_buf begin
                        multi_span_gather!(copies, from_val, spans)
                        send_yield!(copies, to_space.comm, to_space.rank, tag)
                    end
                    stage_release!(kind, stage_buf)
                else
                    send_yield(from_val, to_space.comm, to_space.rank, tag)
                end
            elseif local_rank == to_space.rank
                to_val = poolget(to.handle; uniform=false)
                if pack
                    ainfo = _with_default_acceleration() do
                        aliasing(to_val, dep_mod)
                    end
                    pack = !(ainfo isa NoAliasing || ainfo isa UnknownAliasing)
                end
                if pack
                    spans = memory_spans(ainfo)
                    len = sum(span_len, spans; init=UInt64(0))
                    kind = gpu_memory_kind(to_space.innerSpace)
                    stage_buf = stage_acquire!(kind, len)
                    copies = unsafe_wrap(Array, pointer(stage_buf), Int(len))
                    GC.@preserve stage_buf begin
                        recv_yield!(copies, from_space.comm, from_space.rank, tag)
                        with_context!(to_space.innerSpace)
                        multi_span_scatter!(to_val, copies, spans)
                    end
                    mpi_device_sync(to_space.innerSpace)
                    stage_release!(kind, stage_buf)
                else
                    val = recv_yield(from_space.comm, from_space.rank, tag)
                    # Dense payloads arrive host-staged; materialize in this
                    # space's storage so dep_mod views copy device-to-device
                    val = mpi_localize(to_space.innerSpace, val)
                    move!(dep_mod, to_space.innerSpace, from_space.innerSpace, to_val, val)
                end
            end
        end
    end
    @dagdebug nothing :mpi "[$local_rank] Finished moving from  $(from_space.rank)  to  $(to_space.rank) successfuly\n"
end
function move!(dep_mod::Dagger.RemainderAliasing{<:MPIMemorySpace}, to_space::MPIMemorySpace, from_space::MPIMemorySpace, to::Chunk, from::Chunk)
    @assert to.handle isa MPIRef && from.handle isa MPIRef "MPIRef expected"
    @assert to.handle.comm == from.handle.comm "MPIRef comm mismatch"
    @assert to.handle.rank == to_space.rank && from.handle.rank == from_space.rank "MPIRef rank mismatch"
    local_rank = MPI.Comm_rank(from.handle.comm)
    if to_space.rank == from_space.rank == local_rank
        move!(dep_mod, to_space.innerSpace, from_space.innerSpace, to, from)
    else
        tag = Dagger.in_task() ? to_tag() : to_tag(from.handle)
        @dagdebug nothing :mpi "[$local_rank][$tag] Moving from  $(from_space.rank)  to  $(to_space.rank)\n"
        if local_rank == from_space.rank
            # Gather the source spans into a host buffer (device arrays pack
            # via multi_span_gather! / one KA launch, then a single DtoH)
            len = sum(span_tuple->span_len(span_tuple[1]), dep_mod.spans)
            kind = gpu_memory_kind(from_space.innerSpace)
            stage_buf = stage_acquire!(kind, len)
            copies = unsafe_wrap(Array, pointer(stage_buf), Int(len))
            from_raw = poolget(from.handle; uniform=false)
            with_context!(from_space.innerSpace)
            # Producers may have enqueued work on other tasks' streams
            mpi_device_sync(from_space.innerSpace)
            GC.@preserve stage_buf begin
                multi_span_gather!(copies, from_raw, first.(dep_mod.spans))
                send_yield!(copies, to_space.comm, to_space.rank, tag)
            end
            stage_release!(kind, stage_buf)
        elseif local_rank == to_space.rank
            # Receive the spans
            len = sum(span_tuple->span_len(span_tuple[1]), dep_mod.spans)
            kind = gpu_memory_kind(to_space.innerSpace)
            stage_buf = stage_acquire!(kind, len)
            copies = unsafe_wrap(Array, pointer(stage_buf), Int(len))
            GC.@preserve stage_buf begin
                recv_yield!(copies, from_space.comm, from_space.rank, tag)

                # Scatter the received bytes into the destination spans
                to_raw = poolget(to.handle; uniform=false)
                with_context!(to_space.innerSpace)
                multi_span_scatter!(to_raw, copies, last.(dep_mod.spans))
            end
            # Consumers run on other tasks/streams
            mpi_device_sync(to_space.innerSpace)
            stage_release!(kind, stage_buf)

            # Ensure that the data is visible
            Core.Intrinsics.atomic_fence(:release)
        end
    end

    return
end

# Functions route through the inner processor, so GPU backends can swap
# kernels for device equivalents (e.g. LAPACK.potrf! -> CUSOLVER.potrf!)
move(::MPIOSProc, dst::MPIProcessor, x::Union{Function,Type}) = move(OSProc(), dst.innerProc, x)
move(::MPIOSProc, ::MPIProcessor, x::Chunk{<:Union{Function,Type}}) = poolget(x.handle)

# Out-of-place MPI move for OSProc-labeled Chunks: delegate to the
# MPIProcessor Chunk path so egress runs on the owner and ingress on dest.
function move(src::MPIOSProc, dst::MPIProcessor, x::Chunk)
    @assert src.comm == dst.comm "Multi comm move not supported"
    from = x.processor
    if !(from isa MPIProcessor) || from.rank != x.handle.rank || from.comm != src.comm
        from = MPIProcessor(OSProc(), src.comm, x.handle.rank)
    end
    return move(from, dst, x)
end

function is_local(accel::MPIAcceleration, target)
    return target.rank == MPI.Comm_rank(accel.comm)
end

### SPMD-symmetric datadeps endpoints
#
# Under MPI, datadeps planning (`distribute_tasks!`) runs identically on every
# rank (SPMD). All ranks therefore enter `generate_slot!` /
# `remotecall_endpoint_toplevel` collectively and walk the exact same
# structure-driven path: the aliased-object cache is a per-rank replicated
# store updated symmetrically at the same logical points (no RPC, no
# side-channel registries), aliasing metadata is broadcast from the owner at
# these aligned points, and bulk data is routed owner->destination via P2P
# inside the endpoint.

# A value participating in an SPMD endpoint: the owner rank holds the actual
# value, all other ranks hold only the type and the origin (owner) space.
struct MPIWireValue{T}
    value::Union{Some{T},Nothing}
    space::MPIMemorySpace
    # Aliasing-memo identity of the `Chunk` this value stands in for, or 0 for a
    # sub-value produced by wrapper recursion (which has no chunk of its own).
    # Asking for a wire value's aliasing info means broadcasting from the owner --
    # a global synchronization point during planning -- so when the answer is
    # already memoized for the originating chunk, reuse it (`Dagger.memoized_ainfo`).
    origin_key::UInt
end
MPIWireValue{T}(value::Union{Some{T},Nothing}, space::MPIMemorySpace) where T =
    MPIWireValue{T}(value, space, UInt(0))
wire_type(::MPIWireValue{T}) where T = T
has_value(w::MPIWireValue) = w.value !== nothing
wire_value(w::MPIWireValue) = something(w.value)

memory_space(w::MPIWireValue) = w.space
default_memory_space(accel::MPIAcceleration, w::MPIWireValue) = w.space

function check_uniform(w::MPIWireValue{T}, original=w) where T
    # Compare logical metadata only: the value itself is rank-local. The origin
    # key gates a collective (see `MPIWireValue`), so a rank disagreeing on it
    # would hang in `aliasing` rather than fail loudly.
    return check_uniform(hash(T), original) &&
           check_uniform(w.space, original) &&
           check_uniform(w.origin_key, original)
end

function tochunk(w::MPIWireValue{T}, proc::P, scope::S=Dagger.AnyScope(); kwargs...) where {T,P<:Processor,S}
    if has_value(w)
        return tochunk(wire_value(w), proc, w.space, scope; kwargs...)
    else
        return tochunk(nothing, proc, w.space, scope; type=T, kwargs...)
    end
end

# Remap rank-local memory space stamps (CPURAMMemorySpace(myid()), where
# myid() == 1 on every rank) in aliasing info to the owning rank, so that
# spans from different ranks never falsely alias (SPMD heaps have very
# similar address layouts). `mpi_remap_space` defaults live in core Dagger.
mpi_remap_ptr(ptr::Dagger.RemotePtr{T}, owner::Int) where T =
    RemotePtr{T}(ptr.addr, mpi_remap_space(ptr.space, owner))
mpi_remap_span(span::MemorySpan, owner::Int) =
    MemorySpan(mpi_remap_ptr(span.ptr, owner), span.len)

mpi_remap_ainfo(a::Dagger.NoAliasing, owner::Int) = a
mpi_remap_ainfo(a::Dagger.UnknownAliasing, owner::Int) = a
mpi_remap_ainfo(a::Dagger.ContiguousAliasing, owner::Int) =
    Dagger.ContiguousAliasing(mpi_remap_span(a.span, owner))
mpi_remap_ainfo(a::Dagger.ObjectAliasing, owner::Int) =
    Dagger.ObjectAliasing(mpi_remap_ptr(a.ptr, owner), a.sz)
function mpi_remap_ainfo(a::Dagger.StridedAliasing{T,N,S}, owner::Int) where {T,N,S}
    base_ptr = mpi_remap_ptr(a.base_ptr, owner)
    return Dagger.StridedAliasing{T,N,typeof(base_ptr.space)}(base_ptr,
                                                       mpi_remap_ptr(a.ptr, owner),
                                                       a.base_inds, a.lengths, a.strides)
end
function mpi_remap_ainfo(a::Dagger.TriangularAliasing{T,S}, owner::Int) where {T,S}
    ptr = mpi_remap_ptr(a.ptr, owner)
    return Dagger.TriangularAliasing{T,typeof(ptr.space)}(ptr, a.stride, a.isupper, a.diagonal)
end
function mpi_remap_ainfo(a::Dagger.DiagonalAliasing{T,S}, owner::Int) where {T,S}
    ptr = mpi_remap_ptr(a.ptr, owner)
    return Dagger.DiagonalAliasing{T,typeof(ptr.space)}(ptr, a.stride)
end
mpi_remap_ainfo(a::Dagger.CombinedAliasing, owner::Int) =
    Dagger.CombinedAliasing(Dagger.AbstractAliasing[mpi_remap_ainfo(sub, owner) for sub in a.sub_ainfos])
mpi_remap_ainfo(a::Dagger.AliasingWrapper, owner::Int) =
    Dagger.AliasingWrapper(mpi_remap_ainfo(a.inner, owner))
mpi_remap_ainfo(a::Dagger.AbstractAliasing, owner::Int) = a

# A wire value stands in for the chunk it was unwrapped from, so its aliasing
# info is the chunk's: reuse the memo entry rather than repeating the collective.
function Dagger.aliasing(accel::MPIAcceleration, w::MPIWireValue, dep_mod)
    w.origin_key == 0 && return _aliasing_bcast(accel, w, dep_mod)
    return Dagger.memoized_ainfo(() -> _aliasing_bcast(accel, w, dep_mod),
                                 Dagger.ainfo_memo_key(w.origin_key, dep_mod))
end

mpi_ainfo_owner(w::MPIWireValue) = w.space.rank
mpi_raw_aliasing(w::MPIWireValue, dep_mod) = Dagger.aliasing(wire_value(w), dep_mod)

# All ranks enter collectively; the owner unwraps its local value, all other
# ranks construct a wire proxy carrying only type and origin space. The
# `move_rewrap` recursion below then walks the same path on every rank.
function remotecall_endpoint_toplevel(f, accel::MPIAcceleration, cache::AliasedObjectCache, from_proc, to_proc, from_space, to_space, data::Chunk)
    local_rank = MPI.Comm_rank(accel.comm)
    T = chunktype(data)
    # The chunk's identity alone: `aliasing` combines it with the `dep_mod` to
    # form the same memo key `ainfo_memo_key` would.
    origin_key = Dagger._identity_hash(data)
    w = if local_rank == from_space.rank
        MPIWireValue{T}(Some{T}(unwrap(data)), from_space, origin_key)
    else
        MPIWireValue{T}(nothing, from_space, origin_key)
    end
    return f(accel, cache, from_proc, to_proc, from_space, to_space, w)::Chunk
end

# Materialize a host-staged received value in the native storage of `space`
# (e.g. upload a host Array into device memory for a GPU destination)
function mpi_localize(space::MemorySpace, value)
    space isa CPURAMMemorySpace && return value
    value isa Array || return value
    return move(OSProc(), first(processors(space)), value)
end

# Inner processor of a possibly-MPI-wrapped processor
mpi_inner_proc(proc::MPIProcessor) = proc.innerProc
mpi_inner_proc(proc::Processor) = proc

# Ensure a processor carries MPI rank metadata for dual-sided OOP move
function as_mpi_proc(proc::MPIProcessor, space::MPIMemorySpace)
    if proc.rank == space.rank && proc.comm == space.comm
        return proc
    end
    return MPIProcessor(proc.innerProc, space.comm, space.rank)
end
as_mpi_proc(proc::Processor, space::MPIMemorySpace) =
    MPIProcessor(proc, space.comm, space.rank)

# Source-half OOP conversion: adapt off the owner's device toward a
# transportable form. Dense device buffers that send_yield can ship
# GPU-direct (or stage itself) are left as-is after a device sync.
function mpi_move_egress(src::MPIProcessor, x)
    if x isa DenseArray && isbitstype(eltype(x)) && !(x isa Array)
        mpi_device_sync(x)
        return x
    end
    return move(src.innerProc, OSProc(), x)
end

# Dest-half OOP conversion: adapt a received (often host-staged) value
# into the destination inner processor's native storage (e.g. HtoD).
mpi_move_ingress(dst::MPIProcessor, x) = move(OSProc(), dst.innerProc, x)

# Rank-aware out-of-place move: egress on the source rank, ingress on the
# destination rank. Distributed can stay dest-pull; MPI needs both sides.
function move(src::MPIProcessor, dst::MPIProcessor, x)
    @assert src.comm == dst.comm "Multi comm move not supported"
    local_rank = MPI.Comm_rank(src.comm)
    if src.rank == dst.rank
        if local_rank == src.rank
            return move(src.innerProc, dst.innerProc, x)
        end
        return nothing
    elseif local_rank == src.rank
        return mpi_move_egress(src, x)
    elseif local_rank == dst.rank
        return mpi_move_ingress(dst, x)
    end
    return nothing
end

# Transfer the wire value from its owner to the destination rank, returning a
# uniform Chunk (real payload on the destination, placeholder elsewhere).
# Both ranks run move: owner does egress before send, dest does ingress after
# recv. Chunk type is computed uniformly on every rank via move_type.
function mpi_endpoint_transfer(accel::MPIAcceleration, from_proc, to_proc, from_space, to_space, w::MPIWireValue{T}) where T
    local_rank = MPI.Comm_rank(accel.comm)
    from_mpi = as_mpi_proc(from_proc, from_space)
    to_mpi = as_mpi_proc(to_proc, to_space)
    from_inner = mpi_inner_proc(from_mpi)
    to_inner = mpi_inner_proc(to_mpi)
    T_new = move_type(from_inner, to_inner, T)
    if from_space.rank == to_space.rank
        # No cross-rank movement; the owner (re)wraps its local value,
        # converting between inner spaces (e.g. CPU -> GPU) when they differ
        if local_rank == from_space.rank
            value = move(from_mpi, to_mpi, wire_value(w))
            return tochunk(value, to_proc, to_space; type=T_new)
        else
            return tochunk(nothing, to_proc, to_space; type=T_new)
        end
    end
    tag = to_tag()
    if ipc_type_eligible(T) &&
       ipc_eligible(from_space.innerSpace, to_space.innerSpace) &&
       same_node(accel, from_space.rank, to_space.rank)
        # Same-node device-to-device slot creation: ship only an IPC handle
        if local_rank == from_space.rank
            mpi_ipc_send(wire_value(w), accel.comm, to_space.rank, tag)
            return tochunk(nothing, to_proc, to_space; type=T_new)
        elseif local_rank == to_space.rank
            value = mpi_ipc_recv_materialize(accel.comm, from_space.rank, tag)
            return tochunk(value, to_proc, to_space; type=T_new)
        else
            return tochunk(nothing, to_proc, to_space; type=T_new)
        end
    end
    if local_rank == from_space.rank
        # Owner: egress move, then send the (possibly host-staged) value
        value = move(from_mpi, to_mpi, wire_value(w))
        send_yield(value, accel.comm, to_space.rank, tag)
        return tochunk(nothing, to_proc, to_space; type=T_new)
    elseif local_rank == to_space.rank
        value = recv_yield(accel.comm, from_space.rank, tag)
        # Dest: ingress move into this space's native storage
        value = move(from_mpi, to_mpi, value)
        return tochunk(value, to_proc, to_space; type=T_new)
    else
        return tochunk(nothing, to_proc, to_space; type=T_new)
    end
end

# Uninitialized slot allocation is a property of the rank-local storage, so
# defer to the inner space. Rank identity is already handled by `!=` on the
# spaces themselves (`MPIMemorySpace` compares innerSpace/comm/rank).
Dagger.can_alloc_uninit(space::MPIMemorySpace, ::Type{T}) where {T} =
    Dagger.can_alloc_uninit(space.innerSpace, T)
Dagger.alloc_uninit(space::MPIMemorySpace, ::Type{T}, header) where {T} =
    Dagger.alloc_uninit(space.innerSpace, T, header)

# Allocate the slot on the destination rank without shipping the payload. Only
# the `alloc_header` travels -- dimensions, for an array -- which is the entire
# saving: the buffer's contents are established later by Datadeps' copy-to
# phase. The header is whatever the value type declares, so a type whose shape
# is not its `size` participates without special-casing here.
#
# N.B. Point-to-point, deliberately *not* `bcast_yield`, even though the payload
# is header-sized. Only the destination rank needs the dimensions, so this keeps
# exactly the communication pattern of the `mpi_endpoint_transfer` it replaces:
# one message between the same two ranks. Broadcasting instead makes every rank
# a participant, and an intermediate rank cannot forward while it is blocked
# inside a task awaiting dispatch -- the cross-rank wait cycle described above
# `bcast_tree_children`, seen as a hang on Julia 1.10/1.11.
function mpi_endpoint_alloc(accel::MPIAcceleration, to_proc, to_space, ::Type{T_dest}, w::MPIWireValue) where T_dest
    local_rank = MPI.Comm_rank(accel.comm)
    from_rank = w.space.rank
    if from_rank == to_space.rank
        # Same rank (e.g. CPU -> GPU on one rank): nothing to communicate
        if local_rank == to_space.rank
            value = Dagger.alloc_uninit(to_space, T_dest, Dagger.alloc_header(wire_value(w)))
            return tochunk(value, to_proc, to_space; type=T_dest)
        end
        return tochunk(nothing, to_proc, to_space; type=T_dest)
    end
    # Every rank takes a tag so the sequence stays rank-uniform, exactly as
    # `mpi_endpoint_transfer` does before its own send/recv.
    tag = to_tag()
    if local_rank == from_rank
        send_yield(Dagger.alloc_header(wire_value(w)), accel.comm, to_space.rank, tag)
        return tochunk(nothing, to_proc, to_space; type=T_dest)
    elseif local_rank == to_space.rank
        # Typed from `T_dest` alone: the receiving rank holds no value to derive
        # it from, and a type-level answer is rank-uniform by construction.
        header = recv_yield(accel.comm, from_rank, tag)::Dagger.alloc_header_type(T_dest)
        return tochunk(Dagger.alloc_uninit(to_space, T_dest, header), to_proc, to_space; type=T_dest)
    else
        return tochunk(nothing, to_proc, to_space; type=T_dest)
    end
end

# Generic / wrapper MPIWireValue: leaf transfer, or header+children rebuild
function move_rewrap(accel::MPIAcceleration, cache::AliasedObjectCache, from_proc::Processor, to_proc::Processor, from_space::MemorySpace, to_space::MemorySpace, w::MPIWireValue{T}) where T
    child_types = move_rewrap_child_types(T)
    if child_types === nothing
        # Leaf: materialize the slot on the destination rank, sharing via the
        # aliased-object cache. A dense isbits payload crossing a rank boundary
        # need not be sent at all -- Datadeps' copy-to phase fills the slot, and
        # for a wrapper (e.g. a ChunkView) it sends only the wrapper's own spans
        # instead of the entire backing array. See `slot_may_be_uninit`.
        #
        # N.B. The predicate depends only on the two spaces and the destination
        # type, all rank-uniform, so every rank takes the same branch and the
        # collectives below stay matched.
        T_dest = move_type(mpi_inner_proc(as_mpi_proc(from_proc, from_space)),
                           mpi_inner_proc(as_mpi_proc(to_proc, to_space)), T)
        if Dagger.slot_may_be_uninit(from_space, to_space, T_dest)
            return aliased_object!(cache, w) do w
                return mpi_endpoint_alloc(accel, to_proc, to_space, T_dest, w)
            end
        end
        return aliased_object!(cache, w) do w
            return Dagger.libc_backed(mpi_endpoint_transfer(accel, from_proc, to_proc, from_space, to_space, w))
        end
    end

    local_rank = MPI.Comm_rank(accel.comm)
    child_wires = if has_value(w)
        children, _ = move_rewrap_parts(wire_value(w))
        ntuple(length(child_types)) do i
            CT = child_types[i]
            MPIWireValue{CT}(Some{CT}(children[i]), w.space)
        end
    else
        ntuple(length(child_types)) do i
            CT = child_types[i]
            MPIWireValue{CT}(nothing, w.space)
        end
    end

    child_chunks = map(cw -> move_rewrap(accel, cache, from_proc, to_proc, from_space, to_space, cw), child_wires)
    for cc in child_chunks
        check_uniform(cc.handle)
    end

    mode = move_rewrap_header_mode(T)
    header = if mode === :broadcast
        tag = to_tag()
        # `move_rewrap` is reached from `generate_slot!` inside the per-task
        # planning loop, and each task is handed to `eager_launch!` (and so
        # begins executing, concurrently, on this same rank) before the loop
        # moves on to plan the next task. That means this broadcast is NOT at
        # a "sequential, non-overlapping point" the way the doc comment above
        # `bcast_meta_yield` assumes -- it can race an already-dispatched
        # task's own `execute!`/`poolget` activity on this or another rank.
        # Use the dispatch-decoupled relay so a rank busy running a task's
        # `execute!` still forwards this header on message arrival.
        if local_rank == w.space.rank
            _, hdr = move_rewrap_parts(wire_value(w))
            bcast_meta_yield(accel.comm, w.space.rank, tag, hdr)
        else
            bcast_meta_yield(accel.comm, w.space.rank, tag)
        end
    elseif mode === :none
        nothing
    else
        error("MPIWireValue move_rewrap does not support header mode $mode for $T")
    end

    child_cts = map(chunktype, child_chunks)
    T_new = move_rewrap_result_type(T, child_cts, header)
    if local_rank == to_space.rank
        children_local = map(unwrap, child_chunks)
        v_new = move_rewrap_build(T, children_local, header)
        return tochunk(v_new, to_proc, to_space; type=T_new)
    else
        return tochunk(nothing, to_proc, to_space; type=T_new)
    end
end

# ChunkView: replicated SPMD metadata (inner chunk record + slices exist on
# every rank), so all ranks dispatch symmetrically without a wire proxy
function remotecall_endpoint_toplevel(f, accel::MPIAcceleration, cache::AliasedObjectCache, from_proc, to_proc, from_space, to_space, data::ChunkView)
    return f(accel, cache, from_proc, to_proc, from_space, to_space, data)::Chunk
end

# Share/transfer the backing chunk, then re-create the view on the destination
# (header is replicated SPMD metadata — no broadcast)
function move_rewrap(accel::MPIAcceleration, cache::AliasedObjectCache, from_proc::Processor, to_proc::Processor, from_space::MemorySpace, to_space::MemorySpace, slice::ChunkView)
    local_rank = MPI.Comm_rank(accel.comm)
    children, header = move_rewrap_parts(slice)
    p_chunk = move_rewrap(accel, cache, from_proc, to_proc, from_space, to_space, children[1])
    check_uniform(p_chunk.handle)
    T_view = move_rewrap_result_type(typeof(slice), (chunktype(p_chunk),), header)
    if local_rank == to_space.rank
        v_new = move_rewrap_build(typeof(slice), (unwrap(p_chunk),), header)
        return tochunk(v_new, to_proc, to_space; type=T_view)
    else
        return tochunk(nothing, to_proc, to_space; type=T_view)
    end
end

# A Chunk-wrapped ChunkView cannot cross ranks: the inner chunk record is only
# resolvable on the wrapping rank. `datadeps_arg_wrap` keeps ChunkViews raw
# under MPI, so reaching this indicates a manual `tochunk(::ChunkView)`.
function move_rewrap(accel::MPIAcceleration, cache::AliasedObjectCache, from_proc::Processor, to_proc::Processor, from_space::MemorySpace, to_space::MemorySpace, w::MPIWireValue{T}) where {T<:ChunkView}
    throw(ArgumentError("ChunkView must not be wrapped in a Chunk under MPI; pass the ChunkView directly"))
end

# Owner computes the view's aliasing info locally and broadcasts it
aliasing(accel::MPIAcceleration, x::ChunkView, dep_mod) =
    Dagger.memoized_chunk_aliasing(() -> _aliasing_bcast(accel, x, dep_mod), x, dep_mod)

mpi_ainfo_owner(x::ChunkView) = mpi_ainfo_owner(x.chunk)
function mpi_raw_aliasing(x::ChunkView, dep_mod)
    @assert dep_mod === identity "Dependency modifiers not yet supported for ChunkView: $dep_mod"
    v = view(unwrap(x.chunk), x.slices...)
    # Resolve whole-object containers (e.g. `DSparseArray`) where `v`
    # lives; see `aliasing_unwrapped`.
    return aliasing_unwrapped(v, dep_mod)
end

# The aliased-object cache is a per-rank replicated store; every rank updates
# its own copy at the same logical point during SPMD planning, so no
# cross-rank communication is required here.
function set_stored!(accel::MPIAcceleration, cache::AliasedObjectCache, value::Chunk, ainfo::AbstractAliasing)
    set_stored!(unwrap(cache.chunk)::AliasedObjectCacheStore, cache.space, value, ainfo)
    return
end
function set_key_stored!(accel::MPIAcceleration, cache::AliasedObjectCache, space::MemorySpace, ainfo::AbstractAliasing, value::Chunk)
    set_key_stored!(unwrap(cache.chunk)::AliasedObjectCacheStore, space, ainfo, value)
    return
end

# Chunk may be MPI-backed (MPIRef) but labeled with OSProc; treat source as the owning rank
function move(src::OSProc, dst::MPIProcessor, x::Chunk)
    if x.handle isa MPIRef
        return move(MPIOSProc(x.handle.comm, x.handle.rank), dst, x)
    end
    error("MPI move not supported")
end

move(src::Processor, dst::MPIProcessor, x::Chunk) = error("MPI move not supported")
move(to_proc::MPIProcessor, chunk::Chunk) =
    move(chunk.processor, to_proc, chunk)
move(to_proc::Processor, d::MPIRef) =
    move(MPIOSProc(d.rank), to_proc, d)
move(to_proc::MPIProcessor, x) =
    move(MPIOSProc(to_proc.comm), to_proc, x)

# Non-Chunk task arguments: dual-sided OOP move via MPIProcessor ranks
move(src::MPIOSProc, dst::MPIProcessor, x) =
    move(MPIProcessor(OSProc(), src.comm, src.rank), dst, x)

# Functions route through the inner processor, so GPU backends can swap
# kernels for device equivalents (e.g. BLAS.gemm! -> CUBLAS.gemm!)
move(src::MPIProcessor, dst::MPIProcessor, x::Union{Function,Type}) =
    move(OSProc(), dst.innerProc, x)
move(::MPIProcessor, ::MPIProcessor, x::Chunk{<:Union{Function,Type}}) = poolget(x.handle)

# A chunk of one communicator used by a task of another: only what this process owns can cross.
# A rank-local task may read a chunk of the world that this rank owns, in place; the other
# direction (a shared task reading a rank-local chunk) needs `per_rank` to make it a shared chunk.
function mpi_move_across_comms(src::MPIProcessor, dst::MPIProcessor, x::Chunk)
    h = x.handle
    # Only the world cannot take a chunk of a smaller communicator (it would need every rank to take part)
    dst.comm == MPI.COMM_WORLD &&
        error("A task of the world cannot read a chunk of a rank-local graph or a group; hand it over with `Dagger.per_rank`")
    # Every member of the destination communicator enters the argument move; only the destination rank
    # reads the chunk, and only if this process owns it (nothing crosses communicators over the network)
    dst.rank == MPI.Comm_rank(dst.comm) || return nothing
    if h isa MPIRef && h.rank == MPI.Comm_rank(h.comm)
        return move(src.innerProc, dst.innerProc, poolget(h.innerRef))
    end
    error("A task of a rank-local graph or group cannot read a chunk owned by rank $(h.rank) of another communicator: it is not in this process")
end

function move(src::MPIProcessor, dst::MPIProcessor, x::Chunk)
    src.comm == dst.comm || return mpi_move_across_comms(src, dst, x)
    if Dagger.Sch.SCHED_MOVE[]
        # SPMD argument move at task launch: every rank enters; owner runs
        # egress move before send, destination runs ingress after recv.
        # When the chunk is not resident on the destination rank, the owner
        # sends it P2P on the thunk's uniform tag (argument moves run
        # sequentially in argument order, so FIFO matching is safe).
        local_rank = MPI.Comm_rank(dst.comm)
        if x.handle.rank == dst.rank
            if local_rank == dst.rank
                value = poolget(x.handle; uniform=false)
                return move(src, dst, value)
            end
            return nothing
        else
            @assert DATADEPS_THUNK_ID[] != 0 "Cross-rank argument transfer requires the thunk's TID in scope (chunk owner $(x.handle.rank), destination rank $(dst.rank))"
            tag = UInt32(mpi_tag_of(DATADEPS_THUNK_ID[]))
            # Source processor for egress uses the chunk's owning rank
            from = src.rank == x.handle.rank ? src :
                   MPIProcessor(src.innerProc, src.comm, x.handle.rank)
            if local_rank == x.handle.rank
                value = move(from, dst, poolget(x.handle; uniform=false))
                send_yield(value, dst.comm, dst.rank, tag)
                return nothing
            elseif local_rank == dst.rank
                value = mpi_poisonable(x.handle) do
                    recv_yield(dst.comm, x.handle.rank, tag)
                end
                return move(from, dst, value)
            end
            return nothing
        end
    else
        uniform = uniform_execution()
        # Either we're uniform (so everyone cooperates), or we're unwrapping locally
        if !uniform
            @assert src.rank == MPI.Comm_rank(src.comm) "Unwrapping not permitted"
            @assert src.rank == x.handle.rank == dst.rank
        end
        return poolget(x.handle; uniform)
    end
end

gpu_kernel_backend(proc::MPIProcessor) = gpu_kernel_backend(proc.innerProc)

# Without this, `task_processor()` inside a spawned allocation task returns the
# `MPIProcessor` wrapper (that's what the scheduler assigns), which has no
# matching backend-specific `allocate_array_func` method (those are all
# defined on the raw device proc, e.g. `CuArrayDeviceProc`). It then silently
# falls through to the generic identity fallback and allocates a plain CPU
# array instead of a device array, even though the chunk is (correctly, after
# the scope fix above) recorded as living on that GPU.
Dagger.allocate_array_func(proc::MPIProcessor, f) = Dagger.allocate_array_func(proc.innerProc, f)

# Same forwarding as above: `task_processor()` inside `multi_span_copy!`'s
# `gpu_kernel_lock` call sees the `MPIProcessor` wrapper, so a backend's
# override (keyed on its raw device proc type, e.g. `CLArrayDeviceProc`) would
# otherwise never fire under MPI.
Dagger.gpu_kernel_lock(f, proc::MPIProcessor) = Dagger.gpu_kernel_lock(f, proc.innerProc)

# And again for the sparse tile allocators, which each GPU × SparseArrays
# extension overrides on its raw device proc. Falling through to the host
# default here is worse than a slow path: the tile is built as a host CSC, but
# the chunk is still recorded on the device, so nothing ever moves it and the
# host operand reaches a device `mul!` — which fails on scalar indexing of the
# device vector. Only a re-tiling allocation (`repartition`, `spzeros`) takes
# this path, so it stayed hidden while every sparse tile came from `distribute`
# (whose `move` does dispatch on the unwrapped proc).
Dagger.allocate_sparse_zeros(proc::MPIProcessor, ::Type{T}, dims::Dims) where T =
    Dagger.allocate_sparse_zeros(proc.innerProc, T, dims)
Dagger.allocate_sparse_rand(proc::MPIProcessor, ::Type{T}, dims::Dims, sparsity::AbstractFloat) where T =
    Dagger.allocate_sparse_rand(proc.innerProc, T, dims, sparsity)

# Owner-local payload that preserves the Chunk's SPMD-uniform chunktype after
# Sch unwraps a Chunk to a device value (e.g. Matrix chunktype + CuArray value).
# Without this, promote_op/chunktype diverge across ranks (CuArray vs Matrix).
struct MPILocalArg{T}
    value
end
chunktype(::MPILocalArg{T}) where T = T
mpi_unwrap_arg(a::MPILocalArg) = a.value
mpi_unwrap_arg(a) = a

function bind_moved_argument(::MPIAcceleration, original, moved)
    if moved === nothing && (original isa Chunk || original isa WeakChunk)
        return original
    elseif (original isa Chunk || original isa WeakChunk) &&
           moved !== nothing && !(moved isa Chunk)
        return MPILocalArg{chunktype(original)}(moved)
    end
    return moved
end

# Exceptions may capture rank-local, non-serializable state; fall back to a
# string summary when they can't go over the wire
function mpi_wire_exception(err)
    try
        Serialization.serialize(IOBuffer(), err)
        return err
    catch
        return ErrorException(sprint(showerror, err))
    end
end

# Result chunk space follows the *value*, not the processor. A GPU-scoped
# task that returns a host `Array` (collect's cat tree) must not be stamped
# VRAM — that label would send the next hop through device IPC.
mpi_result_space(result, proc::MPIProcessor) =
    MPIMemorySpace(value_memory_space(result), proc.comm, proc.rank)

# Decide how much result metadata execute! must broadcast.
# - need_type_bcast: return type/space unknown → full (:ok,T,space)/(:error,ex)
# - !need_type_bcast && nothrow: concrete + proven non-throwing → zero MPI
# - !need_type_bcast && !nothrow: concrete but may throw → status-only (:ok / :error)
#
# Device processors (CUDA/ROCm/…) adapt values (e.g. Matrix→CuArray), so
# promote_op on chunktypes is not a safe SPMD stamp; keep full broadcast there.
#
# N.B. Both inference queries go through Dagger's memos: this runs per task on
# every rank, and an uncached compiler invocation per dispatch costs far more than
# the task bodies it is deciding about.
function mpi_execute_bcast_plan(f, args, proc::MPIProcessor)
    arg_types = map(chunktype, args)
    # One key for both memo lookups: building it splats `arg_types` into a
    # `Type` and allocates, and this runs per task on every rank.
    key = Dagger.call_signature_key(f, arg_types)
    if !(proc.innerProc isa ThreadProc)
        inferred = Dagger.cached_return_type(key, f, arg_types)
        return (; need_type_bcast=true, nothrow=false, inferred)
    end
    inferred = Dagger.cached_return_type(key, f, arg_types)
    # `Nothing` is a concrete type and is deliberately NOT forced onto the
    # broadcast path: a `nothing` return (the common in-place / mutating task)
    # is fully known on every rank (all ranks stamp `Chunk{Nothing}` and
    # `memory_space(nothing, proc)`), so it can take the concrete fast path and
    # skip metadata traffic. `Union{}` (function always throws) and `Any`
    # (inference gave up) are not concrete and still need the full broadcast.
    need_type_bcast = !isconcretetype(inferred) || inferred === Union{} ||
                      inferred === Any
    if need_type_bcast
        return (; need_type_bcast=true, nothrow=false, inferred)
    end
    nothrow = Dagger.cached_nothrow(key, f, arg_types)
    return (; need_type_bcast=false, nothrow, inferred)
end

# --- Running a task on a free thread of its rank --------------------------------------
#
# `execute!(::ThreadProc)` binds the function to the processor's thread, so an MPI task
# waits behind anything that occupies that thread without yielding (a long kernel, a
# rank-local task), whichever thread the scheduler happened to name. Measured: a task
# placed on a thread busy for 1.5 s waited 1.25 s, an unscoped one 2.2 s, while the
# other threads of the rank sat idle. Only a thread somebody asked for -- a scope
# naming exactly that processor, which is what Datadeps and explicit pinning use --
# is a promise; otherwise the choice is the runtime's and need not be kept.

# `scope` names one processor: its thread was requested. A Datadeps task (tagged) names its processor
# because the plan has to say which rank runs it, not because it needs that thread; with
# `Dagger.free_datadeps_threads!` it runs on any free thread of its rank
mpi_thread_requested(opts::Options) =
    mpi_task_scope(opts) isa Dagger.ExactScope && !(Dagger.FREE_DATADEPS_THREADS[] && opts.tag !== nothing)

# --- The rank gate: a ready queue with a concurrency limit and priorities for the tasks of a rank --------------
#
# Under MPI every task has occupancy 0, so Dagger's processor queues never hold one back: each task that is ready
# starts at once as a Julia task, and Julia runs them first come first served on the threads of the rank. A flood of
# long tasks (250 walk tiles of 30 ms on 8 threads = ~0.9 s of backlog) then delays a small urgent task submitted
# after it (the export the other ranks wait for) by the whole backlog: measured, with `LLM_info/bench/tiles_latency.jl`,
# 98-211 ms against 0-1 ms when the same work is 4 self-scheduling workers, and in the Barnes-Hut application one task per
# tile was 60-80 % slower under MPI because the other ranks finished seconds later. The gate gives the rank what a
# shared-memory processor queue has: at most `cap - reserve` ordinary tasks run at once (the rest wait, holding no thread),
# `reserve` slots are kept for urgent tasks (`priority > 0`), and waiting tasks are granted slots by priority, then arrival.
# It wraps only the call of the task's function (arguments are already moved, the result is not yet broadcast), so a task
# holds a slot only while it computes. Opt-in: `JULIA_DAGGER_MPI_RANK_GATE=1` / `Dagger.mpi_rank_gate!(true)`.
mutable struct RankGate
    const lock::ReentrantLock
    const cap::Int
    const reserve::Int
    running::Int
    seq::UInt64
    const waiters::Vector{Tuple{Int,UInt64,Base.Event}}      # (priority, arrival, wake-up)
end
RankGate(cap::Int, reserve::Int) = RankGate(ReentrantLock(), max(1, cap), clamp(reserve, 0, max(0, cap - 1)), 0, UInt64(0),
                                           Tuple{Int,UInt64,Base.Event}[])
const MPI_RANK_GATE_ON = Ref(false)
const MPI_RANK_GATE = Ref{Union{Nothing,RankGate}}(nothing)
function Dagger.mpi_rank_gate!(on::Bool=true; cap::Int=Threads.nthreads(:default),
                               reserve::Int=parse(Int, get(ENV, "JULIA_DAGGER_MPI_RANK_GATE_RESERVE", "1")))
    MPI_RANK_GATE[] = on ? RankGate(cap, reserve) : nothing
    MPI_RANK_GATE_ON[] = on
    return on
end
gate_limit(g::RankGate, priority::Int) = priority > 0 ? g.cap : g.cap - g.reserve

function gate_acquire!(g::RankGate, priority::Int)
    ev = nothing
    @lock g.lock begin
        if g.running < gate_limit(g, priority) && isempty(g.waiters)
            g.running += 1
        else
            ev = Base.Event()
            push!(g.waiters, (priority, g.seq += 1, ev))
            # a slot may be free for this task even though others wait (they may be ordinary tasks blocked by the reserve)
            gate_grant!(g)
        end
    end
    ev === nothing || wait(ev)
    return
end
# Grant free slots to the best waiters (highest priority, then earliest); the lock is held
function gate_grant!(g::RankGate)
    while !isempty(g.waiters)
        best = 0
        for i in eachindex(g.waiters)
            pr, sq, _ = g.waiters[i]
            g.running < gate_limit(g, pr) || continue
            if best == 0 || pr > g.waiters[best][1] || (pr == g.waiters[best][1] && sq < g.waiters[best][2])
                best = i
            end
        end
        best == 0 && return
        _, _, ev = g.waiters[best]
        deleteat!(g.waiters, best)
        g.running += 1
        notify(ev)
    end
end
function gate_release!(g::RankGate)
    @lock g.lock begin
        g.running -= 1
        gate_grant!(g)
    end
    return
end

# The task that runs `execute!` is a pooled, migratable task with its TLS in place, so
# the function can simply be called: Julia runs it on whichever thread is free
function mpi_run_unbound(f, args...; kwargs...)
    gate = MPI_RANK_GATE_ON[] ? MPI_RANK_GATE[] : nothing
    if gate !== nothing
        opts = Dagger.get_tls().task_spec.options
        gate_acquire!(gate, opts === nothing ? 0 : something(opts.priority, 0))
        try
            return mpi_run_unbound_call(f, args...; kwargs...)
        finally
            gate_release!(gate)
        end
    end
    return mpi_run_unbound_call(f, args...; kwargs...)
end
function mpi_run_unbound_call(f, args...; kwargs...)
    try
        return @invokelatest f(args...; kwargs...)
    catch err
        err isa InterruptException && rethrow()
        rethrow(CapturedException(err, catch_backtrace()))
    end
end

# Start the task of an MPI processor already pinned to the thread of its inner processor.
# Without this the task is migratable, and `execute!(::ThreadProc)` then misses its inline
# fast path: it creates a second task pinned to the thread, schedules it and waits, which
# measured 160-190 us per task (a dependent chain of tasks pinned to one thread: 387 us per
# link at 4 ranks x 16 threads, of which 161 us was this hand-over). Only for processors of
# this rank, and not for a task that asked for no particular thread while free threads are on.
function Dagger.Sch.task_tid_for_processor(proc::MPIProcessor{Dagger.ThreadProc}, task)
    proc.rank == MPI.Comm_rank(proc.comm) || return nothing
    if Dagger.FREE_MPI_THREADS[]
        opts = task.options
        (opts !== nothing && mpi_thread_requested(opts)) || return nothing
    end
    return Dagger.Sch.task_tid_for_processor(proc.innerProc)
end

function mpi_execute_inner(proc::MPIProcessor, f, args...; kwargs...)
    if Dagger.FREE_MPI_THREADS[] && proc.innerProc isa ThreadProc && Dagger.in_task() &&
       !mpi_thread_requested(Dagger.get_tls().task_spec.options)
        return mpi_run_unbound(f, args...; kwargs...)
    end
    return execute!(proc.innerProc, f, args...; kwargs...)
end

# A task that is not part of a Datadeps region (no tag option) generates ref ids only while it
# is moved to and executed on its processor, never during planning, so once `execute!` returns
# nobody takes another id for its thunk id and its sub-counter is dead. Without this the table
# grew by one entry per task until the next Datadeps `wait_all`, which a program that only uses
# `@spawn` never reaches. Datadeps tasks (tagged) keep the later cleanup: their planning shares
# the key with their execution, and reclaiming between the two would collide on sub-ids.
function execute!(proc::MPIProcessor, f, args...; kwargs...)
    if Dagger.in_task()
        opts = Dagger.get_tls().task_spec.options
        if opts !== nothing && opts.tag === nothing
            tid = sch_handle().thunk_id.id
            try
                # Opt-in delegation (`lend=true`): one field read for every other task
                opts.lend === true && return mpi_execute_body(mpi_lend_state(proc, f, opts), proc, f, args...; kwargs...)
                return mpi_execute_body(proc, f, args...; kwargs...)
            finally
                mpi_cleanup_tid(tid)
            end
        end
    end
    return mpi_execute_body(proc, f, args...; kwargs...)
end

include("MPIExtDelegation.jl")

mpi_execute_body(proc::MPIProcessor, f, args...; kwargs...) =
    mpi_execute_body(nothing, proc, f, args...; kwargs...)

# What the owner calls to run the function itself: plainly, or (a task that may be lent, see
# `mpi_lend_state`) through the lend pool. A separate method per `lend` type, so that the code of a
# task that does not lend is compiled exactly as before.
mpi_owner_run(::Nothing, proc::MPIProcessor, f, raw_args::Tuple, kwargs) =
    mpi_execute_inner(proc, f, raw_args...; kwargs...)
mpi_owner_run(lend, proc::MPIProcessor, f, raw_args::Tuple, kwargs) =
    mpi_lend_run(lend, proc, f, raw_args, kwargs)

function mpi_execute_body(lend::Union{Nothing,LendState}, proc::MPIProcessor, f, args...; kwargs...)
    local_rank = MPI.Comm_rank(proc.comm)
    islocal = local_rank == proc.rank
    inplace_move = f === move!
    tag = to_tag()
    # Plan from SPMD-uniform chunktypes (Chunk / MPILocalArg); run on unwrapped values
    raw_args = map(mpi_unwrap_arg, args)

    if inplace_move
        # Copy tasks are dest-scoped, but every rank runs move!. Bind the
        # local endpoint's device (source vs dest), not always dest's
        # mirrored innerProc — otherwise multi-GPU ranks activate the wrong
        # context before DtoH/gather. Spectators use ThreadProc so no
        # unrelated GPU context is set.
        to_space = raw_args[2]::MPIMemorySpace
        from_space = raw_args[3]::MPIMemorySpace
        local_proc = if local_rank == to_space.rank
            first(processors(to_space.innerSpace))
        elseif local_rank == from_space.rank
            first(processors(from_space.innerSpace))
        else
            ThreadProc(myid(), 1)
        end
        execute!(local_proc, f, raw_args...; kwargs...)
        space = memory_space(nothing, proc)::MPIMemorySpace
        dest_type = chunktype(args[4])
        return tochunk(nothing, proc, space; type=dest_type)
    end

    # A communicator of one rank (a one-rank job, or a rank-local graph): nobody to tell about the
    # status, the type or the space of the result, so there is nothing to plan or to broadcast
    if MPI.Comm_size(proc.comm) == 1
        result = mpi_owner_run(lend, proc, f, raw_args, kwargs)
        space = mpi_result_space(result, proc)
        return tochunk(result, proc, space; type=typeof(result))
    end

    plan = mpi_execute_bcast_plan(f, args, proc)

    # Concrete + nothrow: type/space known locally and the call cannot throw,
    # so non-owners need no status or metadata traffic. Stamp the inferred
    # type on every rank so chunktype stays SPMD-uniform.
    if !plan.need_type_bcast && plan.nothrow
        if islocal
            result = mpi_owner_run(lend, proc, f, raw_args, kwargs)
            space = mpi_result_space(result, proc)
            return tochunk(result, proc, space; type=plan.inferred)
        else
            space = memory_space(nothing, proc)::MPIMemorySpace
            return tochunk(nothing, proc, space; type=plan.inferred)
        end
    end

    # Concrete but may throw: broadcast only status (no T/space on the wire).
    # Type inference still skips metadata; poison keeps SPMD aligned on error.
    if !plan.need_type_bcast
        if mpi_failure_only(Dagger.in_task() ? Dagger.get_tls().task_spec.options : nothing)
            # Status only on failure (see "Failure-only task status"): nobody waits
            # for success, so a rank that is not the owner stamps its placeholder at once
            if islocal
                # N.B. A failure reaches the other ranks from `task_failed!`, which
                # covers every way this task can fail, not only an error in `f`
                result = mpi_owner_run(lend, proc, f, raw_args, kwargs)
                space = mpi_result_space(result, proc)
                return tochunk(result, proc, space; type=plan.inferred)
            else
                space = memory_space(nothing, proc)::MPIMemorySpace
                return tochunk(nothing, proc, space; type=plan.inferred)
            end
        end
        if islocal
            result = try
                mpi_owner_run(lend, proc, f, raw_args, kwargs)
            catch err
                @opcounter :execute_bcast_send_yield
                bcast_meta_yield(proc.comm, proc.rank, tag, (:error, mpi_wire_exception(err)))
                rethrow()
            end
            @opcounter :execute_bcast_send_yield
            bcast_meta_yield(proc.comm, proc.rank, tag, :ok)
            space = mpi_result_space(result, proc)
            return tochunk(result, proc, space; type=plan.inferred)
        else
            msg = bcast_meta_yield(proc.comm, proc.rank, tag)
            if msg isa Tuple && first(msg) === :error
                throw(msg[2])
            end
            space = memory_space(nothing, proc)::MPIMemorySpace
            return tochunk(nothing, proc, space; type=plan.inferred)
        end
    end

    # Non-concrete return type: full status + type/space (or error) broadcast
    if islocal
        result = try
            mpi_owner_run(lend, proc, f, raw_args, kwargs)
        catch err
            @opcounter :execute_bcast_send_yield
            bcast_meta_yield(proc.comm, proc.rank, tag, (:error, mpi_wire_exception(err)))
            rethrow()
        end
        T = typeof(result)
        space = mpi_result_space(result, proc)
        @opcounter :execute_bcast_send_yield
        bcast_meta_yield(proc.comm, proc.rank, tag, (:ok, T, space.innerSpace))
        return tochunk(result, proc, space; type=T)
    else
        msg = bcast_meta_yield(proc.comm, proc.rank, tag)
        if msg[1] === :error
            throw(msg[2])
        end
        _, T, innerSpace = msg
        space = MPIMemorySpace(innerSpace, proc.comm, proc.rank)
        return tochunk(nothing, proc, space; type=T)
    end
end

accelerate!(::Val{:mpi}) = accelerate!(MPIAcceleration())

# Comms with an active MPI acceleration. Guards `initialize_acceleration!`
# idempotency.
const MPI_INITIALIZED_COMMS = LockedObject(Set{MPI.Comm}())

# rank -> system_uuid (node identity), populated once at initialization via
# Allgather — same node definition as Distributed CUDAExt IPC.
const MPI_NODE_UUIDS = LockedObject(Dict{MPI.Comm, Vector{UInt128}}())

# Whether two ranks share a node (false when the map is unavailable)
function same_node(accel::MPIAcceleration, r1::Integer, r2::Integer)
    uuids = lock(MPI_NODE_UUIDS) do node_maps
        get(node_maps, accel.comm, nothing)
    end
    uuids === nothing && return false
    return uuids[r1+1] == uuids[r2+1]
end
# Compat for benches that still have a raw comm
function mpi_same_node(comm::MPI.Comm, r1::Integer, r2::Integer)
    uuids = lock(MPI_NODE_UUIDS) do node_maps
        get(node_maps, comm, nothing)
    end
    uuids === nothing && return false
    return uuids[r1+1] == uuids[r2+1]
end

function initialize_acceleration!(a::MPIAcceleration)
    # Idempotent: user `accelerate!` may be called more than once, but
    # initialization involves collectives (`MPI.Comm_dup`) which must only
    # ever run once per installed session. `accelerate!` skips this when
    # `same_acceleration` holds; after `finalize_acceleration!` the backend
    # entry is gone and re-init is allowed. Per-task execution uses
    # `set_task_acceleration!` in `do_task` (TLS only, no re-init).
    already = lock(MPI_INITIALIZED_COMMS) do comms
        a.comm in comms
    end
    already && return
    # Tiles crossing ranks are libc buffers allocated and freed per region: keep their pages in the heap
    get(ENV, "JULIA_DAGGER_MALLOC_TUNE", "1") in ("1", "true") && Dagger.tune_malloc!()
    get(ENV, "JULIA_DAGGER_MPI_RANK_GATE", "0") in ("1", "true") && Dagger.mpi_rank_gate!(true)
    if !MPI.Initialized()
        MPI.Init(;threadlevel=:multiple)
    end
    lock(MPI_INITIALIZED_COMMS) do comms
        push!(comms, a.comm)
    end
    # Node-locality map for shared-memory/IPC fast paths. Init-time
    # collectives are sanctioned only here (alongside the RPC backend setup);
    # the map is cached for the whole session. Uses system_uuid (same as
    # Distributed CUDAExt) rather than COMM_TYPE_SHARED.
    local_uuid = system_uuid().value
    node_uuids = MPI.Allgather(local_uuid, a.comm)
    lock(MPI_NODE_UUIDS) do node_maps
        node_maps[a.comm] = node_uuids
    end
    # Dedicated broadcast communicator + per-rank relay for per-task metadata
    # broadcasts (see `bcast_meta_yield`). `Comm_dup` is collective and, like
    # `Allgather` above, is sanctioned only at init.
    start_bcast_relay!(a.comm)
    ctx = Dagger.Sch.eager_context()
    sz = MPI.Comm_size(a.comm)
    lock(ctx) do
        for i in 0:(sz-1)
            push!(ctx.procs, MPIOSProc(a.comm, i))
        end
        unique!(ctx.procs)
    end
    # SPMD planning can call `rand`/`randperm`; keep default RNGs aligned.
    sync_mpi_rng!(a.comm)
    check_mpi_rng_coherent!(a.comm)
end

function finalize_acceleration!(a::MPIAcceleration)
    stop_bcast_relay!(a.comm)
    lock(MPI_INITIALIZED_COMMS) do comms
        delete!(comms, a.comm)
    end
    lock(MPI_NODE_UUIDS) do node_maps
        delete!(node_maps, a.comm)
    end
    ctx = Dagger.Sch.eager_context()
    lock(ctx) do
        filter!(p -> !(p isa MPIOSProc && p.comm == a.comm), ctx.procs)
    end
    return nothing
end

"""
    mpi_propagate_chunk_types!(tasks, accel::MPIAcceleration, expected_type)

Ensure all ranks use the same concrete type for the given tasks by setting
each task's options.return_type to expected_type when it is concrete.
This allows chunktype(task) to return the concrete type on every rank
without an MPI allgather of actual result types.
"""
function mpi_propagate_chunk_types!(tasks, accel::MPIAcceleration, expected_type)
    isconcretetype(expected_type) || return
    for t in tasks
        if t isa Thunk
            if t.options !== nothing
                # Respect a more specific tile type already set by the spawner
                # (e.g. `DSparseArray` from sparse allocators).
                if t.options.return_type === nothing
                    t.options.return_type = expected_type
                end
            else
                t.options = Options(return_type=expected_type)
            end
        end
    end
    return
end

# Deterministic round-robin assignment of array blocks to MPI processors:
# every rank computes the same grid, so block ownership is uniform by
# construction (the scheduler's measured costs are rank-local and cannot be
# used for placement decisions under SPMD).
#
# This CPU-only grid only applies when the ambient scope is unrestricted
# (`DefaultScope()`). When the caller has narrowed the scope explicitly (e.g.
# `with_options(;scope=<gpu scope>)` around a GPU-targeted allocation, as the
# MPI x GPU stencil suite does), defer to the ambient scope instead by
# returning `nothing`, mirroring the base (non-MPI) Acceleration's
# `default_procgrid`: `procgrid_scope` then falls back to `get_compute_scope()`
# per chunk, so every allocation task's compute_scope matches the datadeps
# region's `all_scope` and round-robins across the caller's chosen processors.
# Hard-coding the CPU-only grid unconditionally would otherwise place every
# chunk on a `ThreadProc`, which conflicts with a GPU-only ambient scope and
# raises a `SchedulingException`.
function default_procgrid(accel::MPIAcceleration, nblocks::NTuple{N,Int}) where N
    Dagger.get_compute_scope() == Dagger.DefaultScope() || return nothing
    return CyclicProcGrid(uniform_mpi_processors(accel), nblocks)
end

function post_stage_array_chunks!(accel::MPIAcceleration, tasks, eltype::Type{T}, nd::Int) where {T}
    mpi_propagate_chunk_types!(tasks, accel, Array{eltype, nd})
    return tasks
end

# The block grid of an array is the same on every rank, so a block placed on one processor has a
# known rank at spawn time. The tasks that make the blocks run inside a Datadeps region (they
# cannot be elided and are not failure-only), but the tasks that read a block can: they only
# need to know who owns it (`mpi_arg_participates`).
function Dagger.note_chunk_placement!(accel::MPIAcceleration, task, scope)
    if accel.comm == MPI.COMM_WORLD && scope isa Dagger.ExactScope && scope.processor isa MPIProcessor
        task.placed = scope.processor.rank
    end
    return
end

# Processors belong to a communicator: a rank-local graph (communicator of size one) must not
# be placed on the processors of the world, and the other way round
accel_matches_proc(accel::MPIAcceleration, proc::MPIOSProc) = proc.comm == accel.comm
accel_matches_proc(accel::MPIAcceleration, proc::MPIClusterProc) = proc.comm == accel.comm
accel_matches_proc(accel::MPIAcceleration, proc::MPIProcessor) = proc.comm == accel.comm
accel_matches_proc(accel::MPIAcceleration, proc) = false

# --- Owner elision --------------------------------------------------------------
#
# Under SPMD every rank builds, places and "executes" every task, whether or not
# it takes part: a rank that neither runs a task nor owns data the task reads pays
# nearly the full planning cost (measured: 168 us against the owner's 188 us) only
# to stamp an empty result. A task qualifies for elision on a rank when
#
# * its scope is a single `ExactScope(::MPIProcessor)`, so its rank is known at
#   spawn time, on every rank, without consulting the scheduler;
# * that rank is not this one, and this rank owns none of its arguments (an owner
#   has to send its data, so it takes part in the move);
# * its return type is concrete (a non-concrete one needs the type broadcast to every
#   rank), and it reports failures only: `execute!` then does not make the other
#   ranks wait for its status (see "Failure-only task status");
# * every argument is a plain value, an `MPIRef` chunk with no scope restriction,
#   or an earlier task whose owner is known and is not this rank.
#
# Such a task skips thunk creation, scheduling, dispatch and the placeholder
# execution; the rank only takes the task id (done by `eager_spawn`, so ids and
# tags stay uniform) and builds the same placeholder result `execute!` would have.
# Uniformity checks are collective over all ranks, so they disable elision.

# A processor of the one rank `opts` restricts a task to, or `nothing` when the scope
# allows several ranks (or is not a scope of MPI processors). Only its rank and
# communicator are meaningful: a scope that names a whole rank, as
# `Dagger.scope(mpi_rank=r)` does, leaves the choice of thread to the scheduler, and a
# rank that elides the task never learns which thread that was. `scope=` sets both
# `scope` and `compute_scope`; accept either, or both when equal.
function mpi_task_scope(opts::Options)
    return if opts.compute_scope === nothing
        opts.scope
    elseif opts.scope === nothing || opts.scope === opts.compute_scope || opts.scope == opts.compute_scope
        opts.compute_scope
    else
        nothing
    end
end

function mpi_scope_processor(opts::Options)::Union{Nothing,MPIProcessor}
    scope = mpi_task_scope(opts)
    if scope isa Dagger.ExactScope
        proc = scope.processor
        return proc isa MPIProcessor ? proc : nothing
    elseif scope isa Dagger.UnionScope
        return mpi_union_scope_processor(scope)
    end
    return nothing
end

# Scopes are reused (a `with_options(scope=...)` block hands the same object to every
# task spawned under it), so what a union scope names is worked out once per scope.
#
# The key is the scope's address, not `objectid(scope)`: a `UnionScope` holds a tuple with
# one `ExactScope` per processor, and `objectid` hashes all of it, which made a plain rank
# scope (`Dagger.scope(mpi_rank=r)`, one entry per thread) cost ~35 us more to plan than an
# `ExactScope`, three times per task. The entry keeps the scope alive and Julia's GC does not
# move objects, so an address cannot be reused while its entry exists and `===` on a hit
# (pointer equality first) confirms it. Reads take no lock: the table is replaced as a whole.
# `pointer_from_objref` refuses immutable values; a `UnionScope` is one, but it is not a bits type, so it is always
# a heap object and this is the address of that object (never of a copy)
mpi_object_address(x) = UInt(ccall(:jl_value_ptr, Ptr{Cvoid}, (Any,), x))

mutable struct MPIUnionScopeCache
    @atomic table::Dict{UInt,Tuple{Any,Any}}
end
const MPI_UNION_SCOPE_CACHE = MPIUnionScopeCache(Dict{UInt,Tuple{Any,Any}}())
const MPI_UNION_SCOPE_CACHE_LOCK = ReentrantLock()

function mpi_union_scope_processor(scope::Dagger.UnionScope)
    key = mpi_object_address(scope)
    hit = get((@atomic MPI_UNION_SCOPE_CACHE.table), key, nothing)
    hit !== nothing && hit[1] === scope && return hit[2]
    proc = nothing
    scopes = scope.scopes
    if !isempty(scopes) && all(sc -> sc isa Dagger.ExactScope && sc.processor isa MPIProcessor, scopes)
        first_proc = first(scopes).processor
        if all(sc -> sc.processor.rank == first_proc.rank && sc.processor.comm == first_proc.comm, scopes)
            # The same processor on every rank, whatever order the scopes came in
            proc = argmin(short_name, [sc.processor for sc in scopes])
        end
    end
    lock(MPI_UNION_SCOPE_CACHE_LOCK) do
        old = @atomic MPI_UNION_SCOPE_CACHE.table
        table = length(old) >= 256 ? Dict{UInt,Tuple{Any,Any}}() : copy(old)
        table[key] = (scope, proc)
        @atomic MPI_UNION_SCOPE_CACHE.table = table
    end
    return proc
end

# The processors of a single-rank union scope in the order the owner's scheduler sees them
# (`compatible_processors_ordered`: the canonical order), so that a rank which elides the task
# can stamp its placeholder with the processor the owner will pick: under uniform execution
# that is the candidate at `mod(id - 1, n) + 1` (`place_processors_uniform!`; the owner rank
# is either the whole candidate list or not in it, so no preferred block shortens it).
# `mpi_union_scope_processor` names a fixed member, which gives the right rank but, on a
# non-owner, another thread than the owner's: the placeholder and the real result then
# disagreed on `chunk.processor` (BUGS B9). Same address-keyed, lock-free cache as above.
const MPI_UNION_ORDER_CACHE = MPIUnionScopeCache(Dict{UInt,Tuple{Any,Any}}())
const MPI_UNION_ORDER_CACHE_LOCK = ReentrantLock()
function mpi_union_scope_ordered(accel::MPIAcceleration, scope::Dagger.UnionScope)::Union{Nothing,Vector{Processor}}
    key = mpi_object_address(scope)
    hit = get((@atomic MPI_UNION_ORDER_CACHE.table), key, nothing)
    hit !== nothing && hit[1] === scope && return hit[2]::Union{Nothing,Vector{Processor}}
    ordered = nothing
    if mpi_union_scope_processor(scope) !== nothing
        ordered = Dagger.sort_processors_canonical!(Processor[sc.processor for sc in scope.scopes], accel)
        unique!(ordered)
    end
    lock(MPI_UNION_ORDER_CACHE_LOCK) do
        old = @atomic MPI_UNION_ORDER_CACHE.table
        table = length(old) >= 256 ? Dict{UInt,Tuple{Any,Any}}() : copy(old)
        table[key] = (scope, ordered)
        @atomic MPI_UNION_ORDER_CACHE.table = table
    end
    return ordered
end

# The processor the owner's scheduler will run task `uid` on, when its scope names one
# rank; `proc` (the scope's fixed member) otherwise
function mpi_planned_processor(accel::MPIAcceleration, opts::Options, proc::MPIProcessor, uid)::MPIProcessor
    scope = mpi_task_scope(opts)
    scope isa Dagger.UnionScope || return proc
    ordered = mpi_union_scope_ordered(accel, scope)
    ordered === nothing && return proc
    return ordered[mod(Int(uid) - 1, length(ordered)) + 1]::MPIProcessor
end

# At spawn time the scheduler has not yet filled in the execution or result scope
function mpi_task_processor(opts::Options)::Union{Nothing,MPIProcessor}
    (opts.exec_scope === nothing && opts.result_scope === nothing) || return nothing
    return mpi_scope_processor(opts)
end

# Whether the owner of this task reports only failures (see "Failure-only task
# status"). Decided from the task's own options alone, so every rank agrees; it
# holds for every task `elide_task!` may elide. Uniformity checks are collective
# and so rule it out, as does an explicit tag (Datadeps tasks, whose copies and
# waits do not know about failures that arrive this way).
mpi_failure_only(::Nothing) = false
function mpi_failure_only(opts::Options)
    Dagger.ELIDE_FOREIGN_TASKS[] && !CHECK_UNIFORMITY[] && (opts.tag === nothing || Dagger.ELIDE_DATADEPS_TASKS[]) || return false
    return mpi_failure_only(opts, mpi_scope_processor(opts))
end
# With the task's processor already worked out (`elide_task!` needs it for other things too)
function mpi_failure_only(opts::Options, proc::Union{Nothing,MPIProcessor})
    Dagger.ELIDE_FOREIGN_TASKS[] && !CHECK_UNIFORMITY[] && (opts.tag === nothing || Dagger.ELIDE_DATADEPS_TASKS[]) || return false
    return proc !== nothing && (proc.comm == MPI.COMM_WORLD || mpi_is_group(proc.comm))
end

# Whether `local_rank` takes part in moving `v` to the task's rank, or cannot tell
function mpi_arg_participates(v, local_rank::Int, comm::MPI.Comm)
    if v isa Dagger.DTask
        v.stub !== nothing && return mpi_arg_participates(v.stub, local_rank, comm)
        # Ranks are those of the communicator the task belongs to: an argument of another communicator has no
        # rank here, so the rank cannot tell whether it takes part
        a = v.accel
        (a === nothing ? comm == MPI.COMM_WORLD : (a isa MPIAcceleration && a.comm == comm)) || return true
        # `placed`: the rank a block of an array was put on (it does not make the task failure-only)
        where = v.owner >= 0 ? v.owner : v.placed
        return where < 0 || where == local_rank
    elseif v isa Chunk
        # N.B. A scope restriction on the chunk (a `DArray` block has one) only matters through
        # `constrain(task scope, chunk scope)`, which `elide_task!` checks for the task as a whole
        v.handle isa MPIRef || return true
        v.handle.comm == comm || return true
        return v.handle.rank == local_rank
    elseif v isa Dagger.WeakChunk
        return true
    end
    return false
end

# The owner tells everyone when a failure-only task fails, whatever the cause: an
# error in the task, in moving its arguments, or an upstream failure. This runs
# under the scheduler lock, so the send is handed to another task.
function Dagger.Sch.task_failed!(::MPIAcceleration, thunk, value)
    opts = thunk.options
    mpi_failure_only(opts) || return
    proc = mpi_scope_processor(opts)
    MPI.Comm_rank(proc.comm) == proc.rank || return
    ex = mpi_wire_exception(value isa Dagger.DTaskFailedException ? value.ex : value)
    tag = UInt32(mpi_tag_of(thunk.id))
    Dagger.Sch.errormonitor_tracked("mpi_task_failed", Threads.@spawn begin
        bcast_meta_yield(proc.comm, proc.rank, tag, (:error, ex))
    end)
    return
end

# A fetch that throws on the owner still has to take the generic id that the
# broadcast of a successful fetch takes on every other rank (see `poolget`)
function Dagger.fetch_failed_uniform!(accel::MPIAcceleration)
    Dagger.ELIDE_FOREIGN_TASKS[] && !CHECK_UNIFORMITY[] || return
    # The id a successful fetch takes is a generic id of the communicator the task belongs to (and none at all
    # for a communicator of size one): take the same one, wherever the fetch is called from
    MPI.Comm_size(accel.comm) == 1 && return
    cur = Dagger.current_acceleration()
    cur isa MPIAcceleration && cur.comm == accel.comm ? take_ref_id!() : Dagger.with_acceleration(take_ref_id!, accel)
    return
end

# --- Placement at spawn for tasks without a scope ----------------------------------
#
# A task without a scope is placed by the scheduler, so no rank knows the owner when
# the task is created. The placement rule is deterministic and identical on every
# rank, though: the cached canonical order of the candidate processors, the rank that
# owns the task's first MPI argument moved to the front, then a rotation by the task
# id. `elide_task!` therefore applies that rule at spawn time and pins the task to the
# result with an ExactScope: the scheduler is handed a decision instead of making it,
# so it cannot disagree with the ranks that elide the task. Whatever cannot be
# decided at spawn time (an argument whose owner is unknown, a result scope, a
# processor list, a processor that rejects the function or an argument) is left to
# the scheduler and nothing is elided.

struct MPIPlacementRequest
    id::Int
    pref::Union{Int,Nothing}
end
Dagger.task_processor_preference(::MPIAcceleration, req::MPIPlacementRequest, state) = req.pref

# Rank that owns `v`, `nothing` for a plain value (the scheduler ignores those when it
# looks for the owner), `-1` when it cannot be told at spawn time
function mpi_arg_owner(v, comm::MPI.Comm)
    if v isa Dagger.DTask
        v.stub !== nothing && return mpi_arg_owner(v.stub, comm)
        # ranks are those of the communicator the task belongs to
        a = v.accel
        (a === nothing ? comm == MPI.COMM_WORLD : (a isa MPIAcceleration && a.comm == comm)) || return -1
        return v.owner >= 0 ? v.owner : v.placed
    elseif v isa Chunk
        v.handle isa MPIRef || return -1
        v.handle.comm == comm || return -1
        return v.handle.rank
    elseif v isa Dagger.WeakChunk
        return -1
    end
    return nothing
end

function mpi_preplace!(accel::MPIAcceleration, spec, task)
    opts = spec.options
    opts.exec_scope === nothing && opts.result_scope === nothing && opts.proclist === nothing &&
        (opts.single === nothing || opts.single == 0) && opts.restore === nothing &&
        opts.tag === nothing || return false
    (opts.syncdeps === nothing || isempty(opts.syncdeps)) || return false
    scope = if opts.compute_scope === nothing
        opts.scope
    elseif opts.scope === nothing || opts.scope === opts.compute_scope || opts.scope == opts.compute_scope
        opts.compute_scope
    else
        return false
    end
    scope === nothing && (scope = Dagger.DefaultScope())
    fargs = spec.fargs
    f = Dagger.value(fargs[1])
    (f isa Function || f isa Type) || return false
    pref = nothing
    for i in 2:length(fargs)
        arg = fargs[i]
        Dagger.ispositional(arg) || return false
        owner = mpi_arg_owner(Dagger.value(arg), accel.comm)
        owner === nothing && continue
        owner < 0 && return false
        pref === nothing && (pref = owner)
    end
    state = Dagger.Sch.EAGER_STATE[]
    state === nothing && return false
    ctx = Dagger.Sch.eager_context()
    procs = filter(p -> haskey(state.worker_chans, root_worker_id(p)), Dagger.Sch.procs_to_use(ctx, state.sch_options))
    isempty(procs) && return false
    ordered = Dagger.Sch.compatible_processors_ordered(accel, scope, procs)
    isempty(ordered) && return false
    candidates = copy(ordered)
    Dagger.place_processors_uniform!(candidates, accel, MPIPlacementRequest(Int(task.uid), pref), nothing)
    proc = first(candidates)
    proc isa MPIProcessor || return false
    # What `can_use_proc` would check of the processor the scheduler picks first
    Dagger.proc_in_scope(proc, scope) || return false
    Dagger.iscompatible_func(proc, opts, typeof(f)) || return false
    for i in 2:length(fargs)
        Dagger.iscompatible_arg(proc, opts, chunktype(Dagger.value(fargs[i]))) || return false
        # The scheduler also constrains the task's scope by that of every chunk argument
        val = Dagger.value(fargs[i])
        val isa Chunk && !Dagger.proc_in_scope(proc, val.scope) && return false
    end
    # Name the rank, not the thread: which thread runs the task stays the scheduler's
    # (and, with `free_mpi_threads!`, the runtime's) choice. One scope object per
    # (scope, rank), so the scheduler's candidate caches keep hitting.
    opts.compute_scope = mpi_rank_scope(scope, ordered, proc.rank)
    return true
end

const MPI_RANK_SCOPE_CACHE = LockedObject(Dict{Tuple{UInt,Int},Tuple{Any,Any}}())

function mpi_rank_scope(scope, ordered, rank::Int)
    key = (objectid(scope), rank)
    hit = lock(MPI_RANK_SCOPE_CACHE) do cache
        get(cache, key, nothing)
    end
    hit !== nothing && hit[1] === scope && return hit[2]
    ranked = Dagger.UnionScope([Dagger.ExactScope(p) for p in ordered if p isa MPIProcessor && p.rank == rank])
    lock(MPI_RANK_SCOPE_CACHE) do cache
        length(cache) >= 1024 && empty!(cache)
        cache[key] = (scope, ranked)
    end
    return ranked
end

# The scheduler constrains a task's scope by the scope of every chunk argument and fails the task when they
# cannot be satisfied together; a rank that elides the task only needs to know that they can. The result scope is
# `nothing` for every task that gets here (`mpi_task_processor` refuses one), so the chain starts from the compute scope.
# N.B. Computed only for chunk arguments that carry a restriction: `constrain` on the union scope of a whole rank
# costs time proportional to its size, which showed up as +30 us per task at 16 threads when it ran for every task.
function mpi_chunk_scopes_fit(opts::Options, fargs)
    scope = nothing
    for i in 2:length(fargs)
        val = Dagger.value(fargs[i])
        val isa Chunk || continue
        val.scope isa Dagger.AnyScope && continue
        scope === nothing && (scope = @something(opts.compute_scope, opts.scope, Dagger.DefaultScope()))
        scope = Dagger.constrain(scope, val.scope)
        scope isa Dagger.InvalidScope && return false
    end
    return true
end

# Why a task was or was not elided on this rank (read with `Dagger.elision_stats()`), counted where the
# decision is made. One atomic increment per task; only tasks that reach `elide_task!` are counted, which is
# every task while the elision switch is on.
const E_ELIDED, E_OWN_TASK, E_NO_OWNER_KNOWN, E_NOT_FAILURE_ONLY, E_SYNCDEPS_OR_RESTORE,
      E_RETURN_TYPE_NOT_CONCRETE, E_FUNCTION_NOT_PLAIN, E_ARGUMENT_NOT_POSITIONAL,
      E_ARGUMENT_PARTICIPATES, E_SCOPE_CONFLICT, E_NOT_APPLICABLE = 1:11
const ELISION_REASONS = (:elided, :own_task, :no_owner_known, :not_failure_only, :syncdeps_or_restore,
                         :return_type_not_concrete, :function_not_plain, :argument_not_positional,
                         :argument_participates, :scope_conflict, :not_applicable)
const ELISION_COUNTS = [Threads.Atomic{Int}(0) for _ in ELISION_REASONS]
elide_no(reason::Int) = (Threads.atomic_add!(ELISION_COUNTS[reason], 1); false)

function Dagger.elision_stats(::MPIAcceleration)
    return NamedTuple{ELISION_REASONS}(ntuple(i -> ELISION_COUNTS[i][], length(ELISION_REASONS)))
end
function Dagger.reset_elision_stats!(::MPIAcceleration)
    foreach(c -> (c[] = 0), ELISION_COUNTS)
    return
end

function Dagger.elide_task!(accel::MPIAcceleration, spec, task)
    CHECK_UNIFORMITY[] && return elide_no(E_NOT_APPLICABLE)
    # Only tasks of the world are planned by every rank; a rank-local graph has nothing to elide
    accel.comm == MPI.COMM_WORLD || mpi_is_group(accel.comm) || return elide_no(E_NOT_APPLICABLE)
    opts = spec.options
    # Tasks without a scope are placed here, so that every rank knows the owner.
    # N.B. The processor a union scope names is looked up once per task: it is the same
    # answer every time, and each lookup is a hash-table probe on every task.
    proc = mpi_task_processor(opts)
    # A task that named its processor or rank keeps it: it is not lent (placed ones are, see `mpi_lend_state`)
    opts.lend === true && (proc !== nothing || opts.compute_scope !== nothing || opts.scope !== nothing) &&
        (opts.lend = false)
    if proc === nothing && opts.compute_scope === nothing && opts.scope === nothing
        mpi_preplace!(accel, spec, task)
        proc = mpi_task_processor(opts)
    end
    proc === nothing && return elide_no(E_NO_OWNER_KNOWN)
    # Later submissions use this to decide about their own arguments, and `fetch`
    # to stay uniform when the task fails. Only failure-only tasks have an owner.
    mpi_failure_only(opts, proc) || return elide_no(E_NOT_FAILURE_ONLY)
    task.owner = proc.rank
    local_rank = MPI.Comm_rank(proc.comm)
    proc.rank == local_rank && return elide_no(E_OWN_TASK)
    (opts.syncdeps === nothing || isempty(opts.syncdeps) || (Dagger.ELIDE_DATADEPS_TASKS[] && opts.tag !== nothing)) ||
        return elide_no(E_SYNCDEPS_OR_RESTORE)
    opts.restore === nothing || return elide_no(E_SYNCDEPS_OR_RESTORE)
    T = task.metadata.return_type
    (isconcretetype(T) && T !== Union{}) || return elide_no(E_RETURN_TYPE_NOT_CONCRETE)
    fargs = spec.fargs
    f = Dagger.value(fargs[1])
    (f isa Function || f isa Type) || return elide_no(E_FUNCTION_NOT_PLAIN)
    for i in 2:length(fargs)
        arg = fargs[i]
        Dagger.ispositional(arg) || return elide_no(E_ARGUMENT_NOT_POSITIONAL)
        mpi_arg_participates(Dagger.value(arg), local_rank, proc.comm) && return elide_no(E_ARGUMENT_PARTICIPATES)
    end
    mpi_chunk_scopes_fit(opts, fargs) || return elide_no(E_SCOPE_CONFLICT)
    # The placeholder `execute!` stamps on a non-owner, with the id it would get, on the
    # processor the owner will run it on
    proc = mpi_planned_processor(accel, opts, proc, task.uid)
    space = memory_space(nothing, proc)::MPIMemorySpace
    # N.B. `execute!` first takes a ref id for the task's tag when the task has no
    # tag option (`to_tag()`), so the result chunk is the second id of its task.
    # The owner builds the real chunk with that id, and every rank must agree on it.
    stub = with(DATADEPS_THUNK_ID => Int64(task.uid)) do
        opts.tag === nothing && take_ref_id!()
        tochunk(nothing, proc, space; type=T)
    end
    mpi_cleanup_tid(task.uid)
    task.stub = stub
    put!(task.future, stub)
    Threads.atomic_add!(ELISION_COUNTS[E_ELIDED], 1)
    return true
end


# --- Rank-local task graphs: a graph on a communicator of size one --------------------
#
# Under `with_rank_local` the current acceleration is an `MPIAcceleration` over
# `MPI.COMM_SELF`. Everything a communicator has to keep in agreement across its ranks is
# trivially in agreement (one rank), so no other rank plans, places or waits for these tasks
# and the world's uniform ids and tags cannot be shifted by differing numbers of local tasks.
# The tasks are ordinary MPI tasks: MPI processors of this rank (placement by the cached
# deterministic order, no cost estimate), MPI chunks, the MPI execution protocol with size one.

# Task ids of a rank-local graph live above the tag range, so they can never become a tag
# that a task of the world could receive; ids of the world stay below `MPI.tag_ub()`.
const MPI_LOCAL_ID_BASE = 1 << 23
const MPI_LOCAL_ID_COUNTER = Threads.Atomic{Int}(MPI_LOCAL_ID_BASE)

function Dagger.eager_next_id(accel::MPIAcceleration)
    accel.comm == MPI.COMM_WORLD && return Dagger.eager_next_id()
    if accel.comm != MPI.COMM_SELF
        g = lock(MPI_GROUPS) do groups
            get(groups, accel.comm, nothing)
        end
        g === nothing && error("Task ids of a group graph need the group to be registered (`Dagger.with_group`)")
        return UInt64(MPI_GROUP_ID_BASE + (g.index << 24) + Threads.atomic_add!(g.counter, 1))
    end
    return UInt64(Threads.atomic_add!(MPI_LOCAL_ID_COUNTER, 1))
end

const MPI_RANK_LOCAL_ACCELERATION = Ref{Union{MPIAcceleration,Nothing}}(nothing)
const MPI_RANK_LOCAL_LOCK = ReentrantLock()

# The one-rank communicator is registered once, lazily: its processors join the scheduler's
# list (the world's processors are filtered out for it by `accel_matches_proc`).
function mpi_rank_local_acceleration()
    lock(MPI_RANK_LOCAL_LOCK) do
        accel = MPI_RANK_LOCAL_ACCELERATION[]
        accel !== nothing && return accel
        MPI.Initialized() || error("Rank-local task graphs need MPI: call `Dagger.accelerate!(:mpi)` first")
        comm = MPI.COMM_SELF
        ensure_children!(comm)
        lock(MPI_NODE_UUIDS) do node_maps
            node_maps[comm] = [system_uuid().value]
        end
        lock(MPI_INITIALIZED_COMMS) do comms
            push!(comms, comm)
        end
        ctx = Dagger.Sch.eager_context()
        lock(ctx) do
            push!(ctx.procs, MPIOSProc(comm, 0))
            unique!(ctx.procs)
        end
        accel = MPIAcceleration(comm)
        MPI_RANK_LOCAL_ACCELERATION[] = accel
        return accel
    end
end

Dagger.with_rank_local(f) = Dagger.with_acceleration(f, mpi_rank_local_acceleration())

# --- Group graphs: a graph on a communicator of k ranks --------------------------------
#
# The one-rank communicator generalized: a task graph that only the members of a communicator plan
# and run (every member runs the same program inside `with_group`, as under the world), with its
# own id counter, its own processors and its own message space. Ranks outside the group never see
# its tasks, so planning per rank does not depend on how many ranks there are in total. What the
# group needs from the application: a communicator (`MPI.Comm_create_group` over the members, or
# `Comm_split`), and the rule that data crosses between groups only where one process is a member
# of both and owns the chunk (the owner reads it in place), as for the one-rank case.

struct MPIGroupState
    index::Int                        # unique across all groups of the job (see `mpi_group_acceleration`)
    counter::Threads.Atomic{Int}      # task ids of this group: MPI_GROUP_ID_BASE + (index << 24) + counter
    accel::MPIAcceleration
end
const MPI_GROUPS = LockedObject(Dict{MPI.Comm,MPIGroupState}())
const MPI_NEXT_GROUP_CANDIDATE = Threads.Atomic{Int}(1)
mpi_is_group(comm::MPI.Comm) = lock(MPI_GROUPS) do groups
    haskey(groups, comm)
end

# Collective over the members of `comm` the first time it is used. The group index that makes the task
# ids of two groups distinct in a process that is a member of both is chosen without any coordination
# between groups: every process reserves a candidate (unique across the job: counter * world size +
# world rank) and the members take the largest one, which is some member's reservation and so
# belongs to this group alone.
function mpi_group_acceleration(comm::MPI.Comm)
    comm == MPI.COMM_WORLD && return MPIAcceleration(comm)
    comm == MPI.COMM_SELF && return mpi_rank_local_acceleration()
    st = lock(MPI_GROUPS) do groups
        get(groups, comm, nothing)
    end
    st !== nothing && return st.accel
    MPI.Initialized() || error("Group graphs need MPI: call `Dagger.accelerate!(:mpi)` first")
    world = MPI.COMM_WORLD
    candidate = Threads.atomic_add!(MPI_NEXT_GROUP_CANDIDATE, 1) * MPI.Comm_size(world) + MPI.Comm_rank(world)
    index = MPI.Allreduce(candidate, max, comm)
    accel = MPIAcceleration(comm)
    mpi_initialize_group!(accel)
    lock(MPI_GROUPS) do groups
        groups[comm] = MPIGroupState(index, Threads.Atomic{Int}(1), accel)
    end
    return accel
end

# `initialize_acceleration!` for a communicator that is not the world: the same node map, broadcast
# relay and processors, without the global side effects (the default RNGs of the members stay as they are)
function mpi_initialize_group!(a::MPIAcceleration)
    lock(MPI_INITIALIZED_COMMS) do comms
        push!(comms, a.comm)
    end
    node_uuids = MPI.Allgather(system_uuid().value, a.comm)
    lock(MPI_NODE_UUIDS) do node_maps
        node_maps[a.comm] = node_uuids
    end
    start_bcast_relay!(a.comm)
    ctx = Dagger.Sch.eager_context()
    lock(ctx) do
        for i in 0:(MPI.Comm_size(a.comm)-1)
            push!(ctx.procs, MPIOSProc(a.comm, i))
        end
        unique!(ctx.procs)
    end
    return
end

Dagger.with_group(f, comm::MPI.Comm) = Dagger.with_acceleration(f, mpi_group_acceleration(comm))

# --- allgather: every rank gets the values of tasks owned by all ranks --------------------------
#
# The pattern "P tasks, one per rank -> a gather task with P arguments -> fetch" moves every result
# to one rank (P point-to-point moves it serializes), then broadcasts the gathered vector: at 104
# ranks and 4 KB per rank that is 138 ms against 2.8 ms for an `MPI.Allgather`. This is the exchange
# itself, with the progress rules of the rest of this file: no blocking MPI call (a thread parked in
# MPI runs no relay and reaches no GC safepoint), sends are posted before the matching receive
# (rendezvous messages would otherwise deadlock in a ring), and every wait is cooperative.
#
# Dissemination allgather with fanout k: before a round a rank holds the contributions of the `have` ranks that
# follow it (cyclically), itself first. In the round it sends its first `min(have, P - j*have)` blocks to the rank
# j*have below it and receives as many from the rank j*have above it, for j = 1..k, so it holds (k+1)*have blocks
# afterwards: ceil(log_(k+1) P) rounds for any P. One round is one cooperative wait chain (about 0.1-0.2 ms on a
# laptop, more on a loaded node: every wait goes through `yield` and shares its thread with the relay), so the
# partners of a round are served concurrently: all sends are posted, then all receives are waited for.
# Messages of a round come from distinct sources, and messages from one source arrive in order, so a single tag
# serves every round and every call (every process calls in the same order).
const MPI_ALLGATHER_FANOUT = Ref(4)

function mpi_allgather_blocks(comm::MPI.Comm, mine::Vector{UInt8})
    rank = MPI.Comm_rank(comm); sz = MPI.Comm_size(comm)
    blocks = Vector{Vector{UInt8}}(undef, sz)
    blocks[rank + 1] = mine
    sz == 1 && return blocks
    tag = compare_all_mpi_tag()
    k = max(1, MPI_ALLGATHER_FANOUT[])
    have = 1
    while have < sz
        sreqs = Tuple{MPI.Request,Int}[]
        for j in 1:k
            cnt = min(have, sz - j * have)
            cnt <= 0 && break
            out = Vector{Vector{UInt8}}(undef, cnt)
            for m in 0:cnt-1
                out[m + 1] = blocks[mod(rank + m, sz) + 1]
            end
            to = mod(rank - j * have, sz)
            push!(sreqs, (MPI.isend(out, comm; dest=to, tag), to))
        end
        for j in 1:k
            cnt = min(have, sz - j * have)
            cnt <= 0 && break
            from = mod(rank + j * have, sz)
            got = recv_yield(comm, from, tag)::Vector{Vector{UInt8}}
            for m in 1:cnt
                blocks[mod(rank + j * have + m - 1, sz) + 1] = got[m]
            end
        end
        for (req, to) in sreqs
            __wait_for_request(req, comm, rank, to, tag, "allgather", "send")
        end
        have = min(have * (k + 1), sz)
    end
    return blocks
end

# The same exchange with the library's own non-blocking collective (MPI_Iallgather for the sizes, MPI_Iallgatherv for the
# bytes), which the MPI implementation runs with its tuned algorithm; this file only waits for the request, cooperatively
# (`__wait_for_request` polls with `MPI.Test` and yields), so it never parks a thread inside MPI. MPI.jl 0.20 wraps the
# blocking `Allgatherv` only, so the low-level `MPI.API` calls are used. Every rank must call it in the same order on a
# communicator (an MPI rule for collectives): `Dagger.allgather` is called from the driver, one call at a time.
# `JULIA_DAGGER_MPI_ALLGATHER=native` (on every rank) selects the library's collective; the default is the hand-written rounds.
# Measured on Fulda (Open MPI), slowest rank, ms, 24 / 48 / 96 ranks, everything but the exchange finished: 4 KB per rank
# rounds 5.0 / 6.3 / 19 against native 7.8 / 11 / 20, 16 KB 7.5 / 22 / 121 against 14 / 18 / 39, 64 KB 34 / 43 / 258 against
# 17 / 28 / 171. In the Barnes-Hut application (2.8 / 5.5 / 10.6 KB per rank at 104 / 52 / 26 ranks) the rounds took 20 / 15 ms
# against 40 / 24 ms at 104 / 52 ranks. So the rounds are better for the small contributions this is meant for (and on MPICH
# on a laptop), the native collective from about 16 KB per rank. A contribution's size is not the same on every rank, so it
# cannot decide the algorithm per call.
const MPI_ALLGATHER_NATIVE = Ref{Union{Bool,Nothing}}(nothing)
function mpi_allgather_native()
    v = MPI_ALLGATHER_NATIVE[]
    if v === nothing
        v = get(ENV, "JULIA_DAGGER_MPI_ALLGATHER", "rounds") == "native"
        MPI_ALLGATHER_NATIVE[] = v
    end
    return v
end

function mpi_allgather_blocks_native(comm::MPI.Comm, mine::Vector{UInt8})
    rank = MPI.Comm_rank(comm); sz = MPI.Comm_size(comm)
    sz == 1 && return Vector{UInt8}[mine]
    # 1. everyone's size
    counts = Vector{Cint}(undef, sz)
    sbuf = MPI.Buffer(Ref(Cint(length(mine))))
    rbuf = MPI.UBuffer(counts, 1)
    req = MPI.Request()
    GC.@preserve counts begin
        MPI.API.MPI_Iallgather(sbuf.data, sbuf.count, sbuf.datatype, rbuf.data, rbuf.count, rbuf.datatype, comm, req)
        MPI.setbuffer!(req, (sbuf, rbuf))
        __wait_for_request(req, comm, rank, -1, UInt32(0), "allgather_sizes", "collective")
    end
    # 2. the bytes
    total = sum(counts; init=0)
    recv = Vector{UInt8}(undef, total)
    vbuf = MPI.VBuffer(recv, counts)
    sbuf2 = MPI.Buffer(mine)
    req2 = MPI.Request()
    GC.@preserve recv mine begin
        MPI.API.MPI_Iallgatherv(sbuf2.data, sbuf2.count, sbuf2.datatype, vbuf.data, vbuf.counts, vbuf.displs, vbuf.datatype, comm, req2)
        MPI.setbuffer!(req2, (sbuf2, vbuf))
        __wait_for_request(req2, comm, rank, -1, UInt32(0), "allgather", "collective")
    end
    blocks = Vector{Vector{UInt8}}(undef, sz)
    off = 0
    for r in 1:sz
        n = Int(counts[r])
        blocks[r] = recv[off+1:off+n]
        off += n
    end
    return blocks
end

# `Dagger.allgather_value`, `Dagger.barrier`: collectives for plain values with the progress rules of this file (no
# thread parked in MPI; see the docstrings in acceleration.jl)
function Dagger.allgather_value(accel::MPIAcceleration, x; comm::MPI.Comm=accel.comm)
    blocks = mpi_allgather_blocks(comm, MPI.serialize(x))
    return Any[MPI.deserialize(b) for b in blocks]
end
function Dagger.barrier(accel::MPIAcceleration; comm::MPI.Comm=accel.comm)
    MPI.Comm_size(comm) == 1 && return nothing
    req = MPI.Ibarrier(comm)
    __wait_for_request(req, comm, MPI.Comm_rank(comm), -1, UInt32(0), "barrier", "collective")
    return nothing
end

function Dagger.allgather(accel::MPIAcceleration, tasks::AbstractVector)
    comm = accel.comm
    rank = MPI.Comm_rank(comm)
    # What this rank knows: the value of every task whose result it owns, or the failure it saw. The
    # result is read from the task's future, not by `fetch(task)`, which would take a generic id when the
    # owner of an elided task failed (see `fetch_failed_uniform!`): nothing here takes an id.
    mine = Pair{Int,Any}[]
    for (i, t) in enumerate(tasks)
        try
            raw = fetch(t.future; move_value=false, unwrap=false, uniform=false)
            raw isa Chunk && raw.handle isa MPIRef ||
                error("Dagger.allgather needs tasks whose results are MPI chunks, got $(typeof(raw))")
            h = raw.handle
            h.comm == comm || error("Dagger.allgather: a task belongs to another communicator than the current one")
            h.rank == rank && push!(mine, i => poolget(h; uniform=false))
        catch err
            err isa InterruptException && rethrow()
            push!(mine, i => CapturedException(err, catch_backtrace()))
        end
    end
    blob = MPI.serialize(mine)
    blocks = mpi_allgather_native() ? mpi_allgather_blocks_native(comm, blob) : mpi_allgather_blocks(comm, blob)
    values = Vector{Any}(undef, length(tasks))
    filled = fill(false, length(tasks))
    failure = nothing
    for blob in blocks
        for (i, v) in MPI.deserialize(blob)::Vector{Pair{Int,Any}}
            if v isa CapturedException
                (failure === nothing || i < failure[1]) && (failure = (i, v))
            else
                values[i] = v; filled[i] = true
            end
        end
    end
    failure === nothing || throw(failure[2])
    all(filled) || error("Dagger.allgather: no process owned the result of task $(findfirst(!, filled))")
    # The values came over the wire untyped: narrow to the concrete type they share (`Vector{Any}` helps nobody)
    return [v for v in values]
end


# Collective over the members. The communicator itself stays the caller's to free.
function Dagger.free_group!(comm::MPI.Comm)
    st = lock(MPI_GROUPS) do groups
        pop!(groups, comm, nothing)
    end
    st === nothing && return
    stop_bcast_relay!(comm)
    lock(MPI_INITIALIZED_COMMS) do comms
        delete!(comms, comm)
    end
    lock(MPI_NODE_UUIDS) do node_maps
        delete!(node_maps, comm)
    end
    ctx = Dagger.Sch.eager_context()
    lock(ctx) do
        filter!(p -> !(p isa MPIOSProc && p.comm == comm), ctx.procs)
    end
    return
end

# A chunk of this rank's rank-local graph, relabelled as a chunk of the world owned by this rank
# (same data, no copy); `id` is the world id that every rank reserved for it.
function mpi_adopt_chunk(c::Chunk, id::MPIRefID, ::Type{T}, comm::MPI.Comm=MPI.COMM_WORLD) where {T}
    h = c.handle::MPIRef
    me = MPI.Comm_rank(comm)
    ref = MPIRef(comm, me, h.size, h.innerRef, id)
    proc = MPIProcessor(c.processor.innerProc, comm, me)
    space = MPIMemorySpace(c.space.innerSpace, comm, me)
    return Chunk{T,typeof(ref),typeof(proc),typeof(c.scope),typeof(space)}(T, c.domain, ref, proc, c.scope, space)
end

# What every other rank holds for rank `r`'s chunk: type and identity, no data
function mpi_placeholder_chunk(proto::Chunk, r::Int, id::MPIRefID, ::Type{T}, comm::MPI.Comm=MPI.COMM_WORLD) where {T}
    ref = MPIRef(comm, r, 0, nothing, id)
    proc = MPIProcessor(proto.processor.innerProc, comm, r)
    space = MPIMemorySpace(proto.space.innerSpace, comm, r)
    return Chunk{T,typeof(ref),typeof(proc),typeof(proto.scope),typeof(space)}(T, Dagger.domain(nothing), ref, proc, proto.scope, space)
end

function Dagger.per_group(f, comm::MPI.Comm, ::Type{T}) where {T}
    me = MPI.Comm_rank(comm)
    P = MPI.Comm_size(comm)
    # One id of the group per member, taken identically by every member before anything member-specific
    # happens (for the world: one world id per rank)
    ids = Dagger.with_group(comm) do
        [take_ref_id!() for _ in 1:P]
    end
    local_chunk = Dagger.with_rank_local() do
        r = f()
        r isa Chunk ? r :
            fetch(r isa Dagger.DTask ? r : Dagger.@spawn(identity(r)); raw=true)
    end
    local_chunk isa Chunk && local_chunk.handle isa MPIRef ||
        error("`per_rank`/`per_group` expects the function to return a task or chunk of the rank-local graph")
    return [r == me ? mpi_adopt_chunk(local_chunk, ids[r+1], T, comm) : mpi_placeholder_chunk(local_chunk, r, ids[r+1], T, comm) for r in 0:P-1]
end
Dagger.per_rank(f, ::Type{T}) where {T} = Dagger.per_group(f, MPI.COMM_WORLD, T)

# Precompile the concrete-MPI specializations of the planner that the first Datadeps region of a process
# would otherwise compile (several seconds on a laptop, ~90 s on the Opteron nodes). The statements come from a
# `--trace-compile` run; a statement that does not match this Dagger/Julia version is skipped.
include("MPIExtPrecompileStatements.jl")
for _stmt in MPI_PRECOMPILE_STATEMENTS
    try
        Core.eval(@__MODULE__, Meta.parse(_stmt))
    catch
    end
end

end # module MPIExt
