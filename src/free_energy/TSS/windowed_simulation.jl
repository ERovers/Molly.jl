function log_windowed_tss_stats!(
    stats::WindowedTSSStats{FT},
    state::TSSState{FT},
    update_window::Int,
    visited_state::Int,
    next_state::Int,
    max_delta_f::FT;
    replica_indices = [1],
    replica_update_windows = [update_window],
    replica_visited_states = [visited_state],
    replica_sampled_next_states = [next_state],
    replica_max_abs_delta_f = [max_delta_f]) where {FT}

    push!(stats.iterations, state.iteration)
    push!(stats.update_window, update_window)
    push!(stats.visited_state, visited_state)
    push!(stats.sampled_next_state, next_state)
    push!(stats.max_abs_delta_f, max_delta_f)
    push!(stats.active_window_history, state.active_window)
    push!(stats.replica_indices, Int.(collect(replica_indices)))
    push!(stats.replica_update_windows, Int.(collect(replica_update_windows)))
    push!(stats.replica_visited_states, Int.(collect(replica_visited_states)))
    push!(stats.replica_sampled_next_states, Int.(collect(replica_sampled_next_states)))
    push!(stats.replica_max_abs_delta_f, FT.(collect(replica_max_abs_delta_f)))
    if isnothing(state.coupling)
        push!(stats.reported_f_history, FT[])
        push!(stats.visit_control_converged, false)
        push!(stats.visit_control_iterations, 0)
        push!(stats.visit_control_max_abs_residual, FT(NaN))
        push!(stats.window_prob_history, FT[])
        push!(stats.visit_control_f_history, FT[])
    else
        coupling = state.coupling
        push!(stats.reported_f_history, tss_free_energies(state))
        push!(stats.visit_control_converged, coupling.converged)
        push!(stats.visit_control_iterations, coupling.iterations)
        push!(stats.visit_control_max_abs_residual, coupling.max_abs_residual)
        push!(stats.window_prob_history, copy(coupling.window_probs))
        push!(stats.visit_control_f_history, copy(coupling.visit_control_f))
    end

    return stats
end

"""
    TSSSample

One TSS sample, passed to the sample loggers of a [`TSSSimulation`](@ref) by
[`Molly.log_tss_sample!`](@ref).

A sample is collected after each block of `n_md_steps` molecular dynamics steps,
from the coordinates at the end of the block, so a cycle collects
`self_adjustment_steps` samples per replica. As the system loggers log the
initial configuration at the start step of a new simulation, the initial
configuration of each replica is also passed as a sample, at that step, in the
first [`simulate!`](@ref) call; its weights and `log_den` use the window
estimator before any update.

# Fields
- `step::Int`: the absolute MD step of the sample, on the same step count as
    the system loggers.
- `replica_index::Int`: the replica that produced the sample.
- `system`: the replica's active [`System`](@ref), holding the sampled
    coordinates, boundary and velocities.
- `active_state::Int`: the global index of the thermodynamic state that
    propagated the coordinates.
- `active_window::Int`: the window of the cycle.
- `state_indices`: the global state indices of the window.
- `reduced_potentials`: the reduced potentials of the sampled coordinates in
    the window states, in the order of `state_indices`.
- `log_den`: the log normalization `logsumexp(f .+ log_dens .- reduced_potentials)`,
    with the window estimator's free energies `f` and log sampling densities
    `log_dens` at the time of the sample.
- `weights`: the conditional probabilities of the window states given the
    sampled coordinates, from which the next active state is drawn.

`system`, `state_indices`, `reduced_potentials` and `weights` reference the
simulation's own arrays, which are reused, so they are valid only during the
call to [`Molly.log_tss_sample!`](@ref) and must not be modified. A logger that
keeps data must copy it. Nothing is copied off the device for the logger: for a
GPU system, `system.coords` is a device array.
"""
struct TSSSample{S, I, V, T}
    step::Int
    replica_index::Int
    system::S
    active_state::Int
    active_window::Int
    state_indices::I
    reduced_potentials::V
    log_den::T
    weights::V
end

"""
    log_tss_sample!(logger, sample::TSSSample)

Record a TSS sample. Called by [`TSSSimulation`](@ref) once per collected sample,
and for the initial configuration, for each logger in `sample_loggers` or
`replica_sample_loggers`.

Custom sample loggers should implement this function. As for system loggers,
the logger decides which samples to record, for example from `sample.step`;
see [`TSSSampleLogger`](@ref) for a logger with a step interval.
"""
function log_tss_sample! end

"""
    TSSSampleLogger(observable::Function, T, n_steps)

A TSS sample logger that stores `observable(sample)::T` for each
[`Molly.TSSSample`](@ref) whose step is a multiple of `n_steps`.

Samples are collected every `n_md_steps` MD steps, so with `n_steps` a multiple
of `n_md_steps` it records every `n_steps ÷ n_md_steps`-th sample of each
replica, at the same steps as a system logger with the same `n_steps`,
including the initial configuration when the start step is a multiple of
`n_steps`.
The observable must copy any array it keeps from the sample.
Access the stored values with `values(logger)`.
"""
struct TSSSampleLogger{T, F}
    observable::F
    n_steps::Int
    history::Vector{T}
end

function TSSSampleLogger(observable::Function, T::DataType, n_steps::Integer)
    n_steps > 0 || throw(ArgumentError("TSSSampleLogger n_steps must be positive."))
    return TSSSampleLogger{T, typeof(observable)}(observable, n_steps, T[])
end

Base.values(logger::TSSSampleLogger) = logger.history

function log_tss_sample!(logger::TSSSampleLogger, sample::TSSSample)
    if (sample.step % logger.n_steps) == 0
        push!(logger.history, logger.observable(sample))
    end
    return logger
end

function Base.show(io::IO, logger::TSSSampleLogger)
    print(io, "TSSSampleLogger with n_steps ", logger.n_steps, ", ",
          length(logger.history), " values recorded")
end

Base.show(io::IO, ::MIME"text/plain", logger::TSSSampleLogger) = show(io, logger)

function log_tss_samples!(sample_loggers, sample::TSSSample)
    for logger in sample_loggers
        log_tss_sample!(logger, sample)
    end
    return sample_loggers
end

# Prepares the initial configuration as `simulate!` does before it runs the
# system loggers at the start step
function prepare_tss_initial_sample!(sys::System, n_threads::Integer)
    sys.coords .= wrap_coords.(sys.coords, (sys.boundary,))
    place_virtual_sites!(sys; n_threads=n_threads)
    return sys
end

mutable struct WindowedTSSReplica{AS, SL}
    active_state::AS
    active_window::Int
    sample_loggers::SL
end

function Base.show(io::IO, replica::WindowedTSSReplica)
    print(io, "WindowedTSSReplica with active state ",
          replica.active_state.active_idx, ", active window ", replica.active_window)
end

Base.show(io::IO, ::MIME"text/plain", replica::WindowedTSSReplica) = show(io, replica)

function log_tss_replica_sample!(replica::WindowedTSSReplica,
                                 estimator::TSSLocalEstimator,
                                 sample,
                                 step::Int,
                                 replica_index::Int,
                                 cycle_window::Int)
    return log_tss_samples!(replica.sample_loggers, TSSSample(
        step,
        replica_index,
        replica.active_state.active_sys,
        replica.active_state.active_idx,
        cycle_window,
        estimator.state_indices,
        sample.reduced_pot,
        sample.log_den,
        sample.weights,
    ))
end

struct WindowedTSSObservation{T, V, PS}
    replica_index::Int
    update_window::Int
    visited_state::Int
    sampled_next_state::Int
    log_den::T
    reduced_pot::V
    weights::V
    adaptive_values::Union{Nothing, Matrix{T}}
    pmf_deconvolution_samples::PS
end

mutable struct WindowedTSSReplicaWorkspace{P, ST, T, R}
    partition::P
    energies::Vector{ST}
    reduced_pot::Vector{T}
    weights::Vector{T}
    scratch::Vector{T}
    log_state_bias::Vector{T}
    rng::R
end

"""
    TSSSimulation(state::TSSState; n_md_steps, n_cycles,
                  self_adjustment_steps=1, log_freq=1000,
                  n_replicas=nothing, first_states=nothing,
                  first_windows=nothing, replica_active_states=nothing,
                  loggers=(), replica_loggers=nothing,
                  sample_loggers=(), replica_sample_loggers=nothing,
                  pmf=nothing, frozen=false, initial_step=0)

A windowed TSS simulation driver.

See [Predescu et al. 2024](https://doi.org/10.1080/10618600.2023.2291108).
Each cycle runs `self_adjustment_steps` blocks of `n_md_steps` molecular
dynamics steps, collects TSS samples, updates window estimators unless
`frozen=true`, and optionally records sampled PMF deconvolution diagnostics.
`initial_step` sets the absolute MD step for a new or resumed simulation.
`loggers` supplies the logger collection for a single-replica simulation.
For multi-replica TSS, use `replica_loggers` to supply one logger collection
per newly constructed replica active system.

`sample_loggers` supplies a collection of TSS sample loggers for a
single-replica simulation, and `replica_sample_loggers` one collection per
replica for multi-replica TSS, with distinct logger objects for each replica.
[`Molly.log_tss_sample!`](@ref) is called with each logger for every collected
[`Molly.TSSSample`](@ref), in adaptive and frozen runs, and for the initial
configuration at the steps where the system loggers log it. A replica's sample loggers
are called by the task that runs that replica, in sample order, so with
`replica_parallel=:threads` the replicas call their own loggers concurrently.
Without sample loggers, no sample is constructed.
Pass `replica_rngs` to [`simulate!`](@ref) to supply one RNG stream per replica;
otherwise, each replica RNG is reseeded from the top-level `rng`.

`replica_parallel` selects how [`simulate!`](@ref) runs the replicas of a cycle: `:serial` one
after another, `:threads` on separate threads for CPU replicas, or `:distributed` on
Distributed.jl worker processes, one per GPU. The default `:auto` picks `:distributed` for
GPU-backed replicas when worker processes are available, `:threads` for multiple CPU replicas
and `:serial` otherwise. With `:distributed` every worker holds every window and the replicas
are dealt out between the workers, so the GPUs run replicas concurrently and the host keeps the
estimators; the number of replicas each worker ran per cycle is recorded in
`state.stats.worker_occupancy`. Add the workers with `addprocs` and load Molly and the GPU
package on them with `@everywhere` beforehand, and pass `gpu_devices` to [`simulate!`](@ref) to
select the devices, one per worker, all visible devices being used by default. PMF
deconvolution is not supported with `:distributed`.
"""
mutable struct TSSSimulation{S, R, W, P}
    state::S
    replicas::Vector{R}
    replica_workspaces::Vector{W}
    pmf::P
    n_md_steps::Int
    n_cycles::Int
    self_adjustment_steps::Int
    log_freq::Int
    frozen::Bool
    current_step::Int
    initial_log_pending::Bool
end

function Base.show(io::IO, sim::TSSSimulation)
    pmf_status = isnothing(sim.pmf) ? "disabled" : "enabled"
    print(io, "TSSSimulation with ", tss_count(length(sim.replicas), "replica"),
          ", ", tss_count(sim.n_cycles, "cycle"), ", ",
          tss_count(sim.n_md_steps, "MD step"), " per cycle, ",
          tss_count(sim.self_adjustment_steps, "self-adjustment step"),
          " per cycle, frozen=", sim.frozen, ", PMF deconvolution ", pmf_status)
end

Base.show(io::IO, ::MIME"text/plain", sim::TSSSimulation) = show(io, sim)

function TSSSimulation(state::TSSState;
                               n_md_steps::Int,
                               n_cycles::Int,
                               self_adjustment_steps = 1,
                               log_freq::Int = 1000,
                               n_replicas = nothing,
                               first_states = nothing,
                               first_windows = nothing,
                               replica_active_states = nothing,
                               loggers = (),
                               replica_loggers = nothing,
                               sample_loggers = (),
                               replica_sample_loggers = nothing,
                               pmf = nothing,
                               frozen::Bool = false,
                               initial_step::Integer = 0)

    n_md_steps > 0 || throw(ArgumentError("n_md_steps must be positive."))
    n_cycles >= 0 || throw(ArgumentError("n_cycles must be non-negative."))
    initial_step >= 0 || throw(ArgumentError("initial_step must be non-negative."))
    if !(self_adjustment_steps isa Integer)
        throw(ArgumentError("self_adjustment_steps must be an integer."))
    end
    self_adjustment_steps > 0 || throw(ArgumentError("self_adjustment_steps must be positive."))
    log_freq > 0 || throw(ArgumentError("log_freq must be positive."))

    replicas = make_windowed_tss_replicas(
        state;
        n_replicas = n_replicas,
        first_states = first_states,
        first_windows = first_windows,
        replica_active_states = replica_active_states,
        loggers = loggers,
        replica_loggers = replica_loggers,
        sample_loggers = sample_loggers,
        replica_sample_loggers = replica_sample_loggers,
    )
    frozen || validate_windowed_tss_replica_history_support(state, replicas)
    if !isnothing(pmf) && !(pmf isa PMFDeconvolution{<:TSSPMFDeconvolutionBackend})
        throw(ArgumentError("TSSSimulation pmf must be created with PMFDeconvolution(tss_state; ...)."))
    end
    if !isnothing(pmf) && pmf.backend.state !== state
        throw(ArgumentError("TSSSimulation pmf must be created from the same TSSState object."))
    end
    share_gpu_workspaces = windowed_tss_replicas_use_gpu(replicas)
    shared_partition = share_gpu_workspaces ? state.state_space.partition : nothing
    replica_workspaces = [
        WindowedTSSReplicaWorkspace(
            state,
            partition = shared_partition,
        )
        for _ in eachindex(replicas)
    ]

    return TSSSimulation(
        state,
        replicas,
        replica_workspaces,
        pmf,
        n_md_steps,
        n_cycles,
        Int(self_adjustment_steps),
        log_freq,
        frozen,
        Int(initial_step),
        true,
    )
end

function WindowedTSSReplicaWorkspace(state::TSSState; partition = nothing)
    workspace_partition = isnothing(partition) ?
                          deepcopy(state.state_space.partition) :
                          partition
    return WindowedTSSReplicaWorkspace(state.estimators, workspace_partition)
end

function WindowedTSSReplicaWorkspace(estimators, partition)
    max_eval_states = maximum(length(estimator.evaluation_state_indices) for estimator in estimators)
    reference_estimator = first(estimators)
    FT = eltype(reference_estimator.f)
    ST = eltype(reference_estimator.energies)

    return WindowedTSSReplicaWorkspace(
        partition,
        Vector{ST}(undef, max_eval_states),
        zeros(FT, max_eval_states),
        zeros(FT, max_eval_states),
        zeros(FT, max_eval_states),
        zeros(FT, max_eval_states),
        MersenneTwister(0),
    )
end

function windowed_tss_replicas_use_gpu(replicas)
    return any(replica -> is_on_gpu(replica.active_state.active_sys), replicas)
end

function replica_count(n_replicas, replica_active_states)
    if isnothing(n_replicas)
        return isnothing(replica_active_states) ? 1 : length(replica_active_states)
    end
    if !(n_replicas isa Integer)
        throw(ArgumentError("n_replicas must be an integer."))
    end
    if n_replicas <= 0
        throw(ArgumentError("n_replicas must be positive."))
    end
    return Int(n_replicas)
end

function normalize_replica_values(values, n_replicas::Int, default, name::AbstractString)
    if isnothing(values)
        return fill(Int(default), n_replicas)
    end
    normalized = Int.(collect(values))
    if length(normalized) != n_replicas
        throw(ArgumentError("$(name) must have length $(n_replicas)."))
    end
    return normalized
end

function normalize_tss_replica_loggers(loggers, replica_loggers, n_replicas::Int)
    if !isnothing(replica_loggers)
        logger_collection_empty(loggers) ||
            throw(ArgumentError("pass either loggers or replica_loggers to TSSSimulation, not both."))
        normalized = collect(replica_loggers)
        if length(normalized) != n_replicas
            throw(ArgumentError("replica_loggers must have length $(n_replicas)."))
        end
        first_type = typeof(first(normalized))
        if !all(logger_set -> typeof(logger_set) == first_type, normalized)
            throw(ArgumentError("all TSS replica_loggers entries must have the same type"))
        end
        validate_replica_loggers(normalized)
        return normalized
    end

    if n_replicas == 1
        return [loggers]
    end

    if !logger_collection_empty(loggers)
        throw(ArgumentError("TSSSimulation loggers can only be used with one replica; " *
                            "pass replica_loggers for multi-replica TSS."))
    end
    return [() for _ in 1:n_replicas]
end

function validate_tss_sample_logger_collection(sample_loggers, name::AbstractString)
    if !(sample_loggers isa Union{Tuple, NamedTuple})
        throw(ArgumentError("$(name) must be a Tuple or NamedTuple of TSS sample loggers."))
    end
    return sample_loggers
end

function normalize_tss_replica_sample_loggers(sample_loggers,
                                              replica_sample_loggers,
                                              n_replicas::Int)
    validate_tss_sample_logger_collection(sample_loggers, "sample_loggers")
    if !isnothing(replica_sample_loggers)
        isempty(sample_loggers) ||
            throw(ArgumentError("pass either sample_loggers or replica_sample_loggers " *
                                "to TSSSimulation, not both."))
        normalized = collect(replica_sample_loggers)
        if length(normalized) != n_replicas
            throw(ArgumentError("replica_sample_loggers must have length $(n_replicas)."))
        end
        for logger_set in normalized
            validate_tss_sample_logger_collection(logger_set, "replica_sample_loggers entries")
        end
        first_type = typeof(first(normalized))
        if !all(logger_set -> typeof(logger_set) == first_type, normalized)
            throw(ArgumentError("all TSS replica_sample_loggers entries must have the same type"))
        end
        validate_replica_loggers(normalized; name = "replica_sample_loggers")
        return normalized
    end

    if n_replicas == 1
        return [sample_loggers]
    end

    if !isempty(sample_loggers)
        throw(ArgumentError("TSSSimulation sample_loggers can only be used with one replica; " *
                            "pass replica_sample_loggers for multi-replica TSS."))
    end
    return [() for _ in 1:n_replicas]
end

function default_tss_replica_windows(state::TSSState,
                                      first_states::AbstractVector{Int})
    return [first(windows_for_state(state, first_state)) for first_state in first_states]
end

function validate_tss_replica_window(state::TSSState,
                                      first_state::Int,
                                      first_window::Int,
                                      replica_i::Int)
    if !(1 <= first_state <= n_states(state.state_space))
        throw(ArgumentError("first_states[$(replica_i)] ($(first_state)) out of range."))
    end
    if !(1 <= first_window <= length(state.windows))
        throw(ArgumentError("first_windows[$(replica_i)] ($(first_window)) out of range."))
    end
    if !window_contains_state(state.windows[first_window], first_state)
        throw(ArgumentError("first_windows[$(replica_i)] must contain first_states[$(replica_i)]."))
    end
    return nothing
end

function make_windowed_tss_replicas(state::TSSState;
                                     n_replicas,
                                     first_states,
                                     first_windows,
                                     replica_active_states,
                                     loggers,
                                     replica_loggers,
                                     sample_loggers,
                                     replica_sample_loggers)
    n_rep = replica_count(n_replicas, replica_active_states)
    if n_rep <= 0
        throw(ArgumentError("n_replicas must be positive."))
    end
    if isnothing(replica_active_states)
        first_state_values = normalize_replica_values(
            first_states,
            n_rep,
            state.active_state.active_idx,
            "first_states",
        )
        replica_loggers_normalized = normalize_tss_replica_loggers(loggers, replica_loggers, n_rep)
        active_states = [
            ActiveThermoState(state.state_space, first_state;
                              loggers=replica_loggers_normalized[i])
            for (i, first_state) in pairs(first_state_values)
        ]
    else
        source_active_states = collect(replica_active_states)
        if length(source_active_states) != n_rep
            throw(ArgumentError("replica_active_states must have length $(n_rep)."))
        end
        first_state_values = [active_state.active_idx for active_state in source_active_states]
        if !isnothing(first_states)
            supplied = normalize_replica_values(first_states, n_rep, first(first_state_values), "first_states")
            if supplied != first_state_values
                throw(ArgumentError("first_states must match replica_active_states active indices."))
            end
        end
        replica_loggers_normalized = normalize_tss_replica_loggers(loggers, replica_loggers, n_rep)
        active_states = [
            sync_active_state_dynamics!(
                ActiveThermoState(state.state_space, source_active_state.active_idx;
                                  loggers=replica_loggers_normalized[i]),
                source_active_state,
            )
            for (i, source_active_state) in pairs(source_active_states)
        ]
    end

    first_window_values = if isnothing(first_windows)
        n_rep == 1 && first_state_values[1] == state.active_state.active_idx ?
        [state.active_window] :
        default_tss_replica_windows(state, first_state_values)
    else
        normalize_replica_values(first_windows, n_rep, state.active_window, "first_windows")
    end

    if n_rep == 1 && first_state_values[1] == state.active_state.active_idx &&
            first_window_values[1] != state.active_window
        throw(ArgumentError("single-replica TSSSimulation must use the " *
                            "TSSState active window; construct the state " *
                            "with the desired first_window instead."))
    end

    replica_sample_loggers_normalized = normalize_tss_replica_sample_loggers(
        sample_loggers,
        replica_sample_loggers,
        n_rep,
    )

    for replica_i in 1:n_rep
        validate_tss_replica_window(
            state,
            first_state_values[replica_i],
            first_window_values[replica_i],
            replica_i,
        )
    end

    return [
        WindowedTSSReplica(
            active_states[replica_i],
            first_window_values[replica_i],
            replica_sample_loggers_normalized[replica_i],
        )
        for replica_i in 1:n_rep
    ]
end

function validate_windowed_tss_replica_history_support(state::TSSState,
                                                        replicas::AbstractVector)
    length(replicas) <= 1 && return nothing
    if !all(estimator -> !isnothing(estimator.history), state.estimators)
        throw(ArgumentError("multireplica TSSSimulation requires history_forgetting " *
                            "to be enabled in TSSState."))
    end
    return nothing
end

function drop_old_windowed_tss_histories!(state::TSSState, history_time::Int)
    for estimator in state.estimators
        isnothing(estimator.history) && continue

        drop_old_tss_epochs!(estimator.history, history_time)
        if tss_recent_count(estimator) > 0
            aggregate_tss_history!(estimator)
            update_tss_sampling_distribution!(estimator)
        end
    end
    return state
end

function check_windowed_tss_replica_invariant(state::TSSState,
                                               replica::WindowedTSSReplica)
    if !(1 <= replica.active_window <= length(state.windows))
        throw(ArgumentError("TSS replica active window $(replica.active_window) out of range."))
    end
    if !window_contains_state(state.windows[replica.active_window], replica.active_state.active_idx)
        throw(ArgumentError("TSS replica active window $(replica.active_window) does not contain " *
                            "active state $(replica.active_state.active_idx)."))
    end
    return replica
end

# The cycle body runs on a worker process in the multi-GPU path and so cannot see the TSSState:
# the window's own state list carries everything the check needs
function check_tss_cycle_state!(estimator::TSSLocalEstimator,
                                 replica::WindowedTSSReplica,
                                 cycle_window::Int,
                                 state_idx::Int,
                                 substep::Int,
                                 label::AbstractString)
    if iszero(estimator.local_index_by_state[state_idx])
        throw(ArgumentError(
            "TSS windowed cycle invariant failed at iteration $(estimator.iteration), " *
            "substep $(substep), fixed cycle window $(cycle_window): $(label) state " *
            "$(state_idx) is not contained in window states $(estimator.state_indices)"
        ))
    end
    if replica.active_window != cycle_window
        throw(ArgumentError(
            "TSS windowed cycle invariant failed at iteration $(estimator.iteration), " *
            "substep $(substep), fixed cycle window $(cycle_window): replica active window " *
            "$(replica.active_window) changed during the cycle"
        ))
    end
    return replica
end

function workspace_view(workspace::WindowedTSSReplicaWorkspace, field::Symbol, n::Int)
    return @view getfield(workspace, field)[1:n]
end

function process_tss_sample!(workspace::WindowedTSSReplicaWorkspace,
                              estimator::TSSLocalEstimator{FT},
                              active_state::ActiveThermoState) where {FT}
    coords = active_state.active_sys.coords
    boundary = active_state.active_sys.boundary
    state_indices = estimator.state_indices
    evaluation_state_indices = estimator.evaluation_state_indices
    n_local = length(state_indices)
    n_eval = length(evaluation_state_indices)

    eval_energies = workspace_view(workspace, :energies, n_eval)
    eval_reduced_pot = workspace_view(workspace, :reduced_pot, n_eval)
    energies = workspace_view(workspace, :energies, n_local)
    reduced_pot = workspace_view(workspace, :reduced_pot, n_local)
    weights = workspace_view(workspace, :weights, n_local)
    scratch = workspace_view(workspace, :scratch, n_local)
    log_state_bias = workspace_view(workspace, :log_state_bias, n_local)

    evaluate_energy_subset!(
        eval_energies,
        workspace.partition,
        coords,
        boundary,
        evaluation_state_indices,
    )
    reduced_potentials!(
        eval_reduced_pot,
        eval_energies,
        estimator.state_space,
        boundary,
        evaluation_state_indices,
    )
    check_tss_finite!(eval_reduced_pot, "evaluation reduced potentials", estimator)
    check_tss_finite!(reduced_pot, "reduced potentials", estimator)

    @. log_state_bias = estimator.f + estimator.log_dens
    check_tss_finite!(log_state_bias, "log state bias", estimator)
    conditional_state_weights!(
        weights,
        log_state_bias,
        reduced_pot,
        scratch,
    )
    check_tss_probabilities!(weights, "conditional weights", estimator)

    @. scratch = log_state_bias - reduced_pot
    log_den = logsumexp(scratch)
    isfinite(log_den) || throw(ArgumentError("TSS log normalization is non-finite " *
                                             "($(log_den)) at iteration " *
                                             "$(estimator.iteration) with active state " *
                                             "$(active_state.active_idx)."))

    return (
        reduced_pot = reduced_pot,
        weights = weights,
        log_den = log_den,
    )
end

function tss_sample_global_state(rng::AbstractRNG,
                                  estimator::TSSLocalEstimator,
                                  weights::AbstractVector)
    idx = sample_state(rng, weights)
    return tss_global_index(estimator, idx)
end

windowed_tss_window_offset(state::TSSState{FT}, window::Int) where {FT} =
    isnothing(state.coupling) ? zero(FT) : FT(state.coupling.window_offsets[window])

function collect_windowed_tss_observation!(state::TSSState{FT},
                                            replica::WindowedTSSReplica,
                                            workspace::WindowedTSSReplicaWorkspace,
                                            pmf_deconvolution,
                                            replica_index::Int,
                                            n_md_steps::Int,
                                            self_adjustment_steps::Int,
                                            n_threads::Int,
                                            initial_step::Int,
                                            log_initial_state::Bool) where {FT}
    check_windowed_tss_invariant(state)
    check_windowed_tss_replica_invariant(state, replica)
    cycle_window = replica.active_window
    observation = run_tss_cycle!(
        replica,
        workspace,
        state.estimators[cycle_window],
        state.state_space,
        pmf_deconvolution,
        replica_index,
        n_md_steps,
        self_adjustment_steps,
        n_threads,
        initial_step,
        log_initial_state,
        windowed_tss_window_offset(state, cycle_window),
    )
    check_windowed_tss_replica_invariant(state, replica)
    return observation
end

# One TSS cycle for one replica, fixed to the window of `estimator`. Sees no TSSState, so it runs
# unchanged on a worker process holding only that window's states
function run_tss_cycle!(replica::WindowedTSSReplica,
                        workspace::WindowedTSSReplicaWorkspace,
                        estimator::TSSLocalEstimator{FT},
                        space::ExtendedStateSpace,
                        pmf_deconvolution,
                        replica_index::Int,
                        n_md_steps::Int,
                        self_adjustment_steps::Int,
                        n_threads::Int,
                        initial_step::Int,
                        log_initial_state::Bool,
                        window_offset::FT) where {FT}
    cycle_window = replica.active_window
    entry_state = replica.active_state.active_idx
    check_tss_cycle_state!(estimator, replica, cycle_window, entry_state, 0, "entry")

    final_visited_state = entry_state
    final_next_state = entry_state
    final_log_den = zero(FT)
    pmf_deconvolution_samples = Any[]

    for substep in 1:self_adjustment_steps
        visited_state = replica.active_state.active_idx
        check_tss_cycle_state!(estimator, replica, cycle_window, visited_state, substep, "visited")

        if log_initial_state && substep == 1 && !isempty(replica.sample_loggers)
            prepare_tss_initial_sample!(replica.active_state.active_sys, n_threads)
            initial_sample = process_tss_sample!(workspace, estimator, replica.active_state)
            log_tss_replica_sample!(replica, estimator, initial_sample, initial_step,
                                    replica_index, cycle_window)
        end

        simulate!(
            replica.active_state.active_sys,
            replica.active_state.active_integrator,
            n_md_steps;
            n_threads = n_threads,
            rng = workspace.rng,
            init_step = initial_step + (substep - 1) * n_md_steps,
            run_loggers = (log_initial_state && substep == 1 ? true : :skipstart),
        )

        sample = process_tss_sample!(workspace, estimator, replica.active_state)
        if !isempty(replica.sample_loggers)
            log_tss_replica_sample!(replica, estimator, sample,
                                    initial_step + substep * n_md_steps,
                                    replica_index, cycle_window)
        end
        final_log_den = sample.log_den
        if substep == self_adjustment_steps
            pmf_deconvolution_sample = collect_tss_pmf_deconvolution_sample(
                pmf_deconvolution,
                estimator,
                replica.active_state;
                window_offset = window_offset,
            )
            if !isnothing(pmf_deconvolution_sample)
                push!(pmf_deconvolution_samples, pmf_deconvolution_sample)
            end
        end
        next_state = tss_sample_global_state(workspace.rng, estimator, sample.weights)
        check_tss_cycle_state!(estimator, replica, cycle_window, next_state, substep,
                               "sampled next")

        final_visited_state = visited_state
        final_next_state = next_state

        if substep < self_adjustment_steps
            set_active_state!(replica.active_state, space, next_state)
        end
    end

    observation = WindowedTSSObservation(
        replica_index,
        cycle_window,
        final_visited_state,
        final_next_state,
        final_log_den,
        copy(workspace_view(workspace, :reduced_pot, length(estimator.state_indices))),
        copy(workspace_view(workspace, :weights, length(estimator.state_indices))),
        tss_covdet_moment_values(
            estimator,
            workspace_view(workspace, :reduced_pot, length(estimator.evaluation_state_indices)),
        ),
        pmf_deconvolution_samples,
    )
    set_active_state!(replica.active_state, space, final_next_state)
    return observation
end

function apply_tss_observation_standard!(estimator::TSSLocalEstimator,
                                          observation::WindowedTSSObservation,
                                          history_time::Int)
    estimator.reduced_pot .= observation.reduced_pot
    estimator.weights .= observation.weights
    return update_tss_estimates!(
        estimator;
        visited_state = observation.visited_state,
        history_time = history_time,
        adaptive_values = observation.adaptive_values,
        update_adaptive_gamma = false,
    )
end

function apply_tss_observation_to_history!(estimator::TSSLocalEstimator,
                                            observation::WindowedTSSObservation,
                                            history_time::Int)
    if isnothing(estimator.history)
        throw(ArgumentError("multireplica TSS observation updates require history forgetting."))
    end

    visited_local = tss_local_index(estimator, observation.visited_state)
    estimator.reduced_pot .= observation.reduced_pot
    update_tss_history!(
        estimator,
        visited_local,
        observation.log_den,
        history_time;
        adaptive_values = observation.adaptive_values,
        aggregate = false,
    )
    estimator.iteration += 1
    return estimator
end

function apply_windowed_tss_observations!(state::TSSState{FT},
                                           observations::AbstractVector) where {FT}
    history_time = state.iteration + 1
    old_f = [copy(estimator.f) for estimator in state.estimators]

    if length(observations) == 1
        observation = only(observations)
        estimator = state.estimators[observation.update_window]
        max_df = apply_tss_observation_standard!(
            estimator,
            observation,
            history_time,
        )
        state.window_update_counts[observation.update_window] += 1
        state.iteration += 1
        drop_old_windowed_tss_histories!(state, state.iteration)
        update_windowed_tss_adaptive_gamma!(state)
        update_windowed_tss_coupling!(state)
        return max_df
    end

    for observation in observations
        estimator = state.estimators[observation.update_window]
        apply_tss_observation_to_history!(estimator, observation, history_time)
        state.window_update_counts[observation.update_window] += 1
    end

    state.iteration += 1
    drop_old_windowed_tss_histories!(state, state.iteration)
    update_windowed_tss_adaptive_gamma!(state)
    update_windowed_tss_coupling!(state)

    max_df = zero(FT)
    for (window_i, estimator) in enumerate(state.estimators)
        max_df = max(max_df, maximum(abs, estimator.f .- old_f[window_i]))
    end
    return max_df
end

function apply_windowed_tss_frozen_observations!(state::TSSState{FT},
                                                  observations::AbstractVector) where FT
    for observation in observations
        state.window_update_counts[observation.update_window] += 1
    end
    state.iteration += 1
    return zero(FT)
end

function validate_windowed_tss_replica_rngs(replica_rngs, workspaces)
    rngs = collect(replica_rngs)
    n_replicas = length(workspaces)
    if length(rngs) != n_replicas
        throw(ArgumentError("replica_rngs must have length $(n_replicas)."))
    end
    if !all(rng -> rng isa AbstractRNG, rngs)
        throw(ArgumentError("all replica_rngs entries must be AbstractRNGs."))
    end
    rng_type = typeof(first(workspaces).rng)
    if !all(rng -> rng isa rng_type, rngs)
        throw(ArgumentError("all replica_rngs entries must have type $(rng_type)."))
    end
    return rngs
end

function seed_windowed_tss_replica_rngs!(sim::TSSSimulation, rng::AbstractRNG)
    for workspace in sim.replica_workspaces
        Random.seed!(workspace.rng, rand(rng, UInt))
    end
    return sim
end

function seed_windowed_tss_replica_rngs!(sim::TSSSimulation, replica_rngs)
    rngs = validate_windowed_tss_replica_rngs(replica_rngs, sim.replica_workspaces)
    for (workspace, rng) in zip(sim.replica_workspaces, rngs)
        workspace.rng = deepcopy(rng)
    end
    return sim
end

function validate_tss_replica_parallel(replica_parallel)
    mode = replica_parallel isa Symbol ? replica_parallel : Symbol(replica_parallel)
    if !(mode in (:auto, :serial, :threads, :distributed))
        throw(ArgumentError("replica_parallel must be one of :auto, :serial, :threads, or :distributed."))
    end
    return mode
end

function windowed_tss_uses_gpu_replicas(sim::TSSSimulation)
    return windowed_tss_replicas_use_gpu(sim.replicas)
end

function resolve_tss_replica_parallel(sim::TSSSimulation,
                                       replica_parallel,
                                       n_threads::Int)
    mode = validate_tss_replica_parallel(replica_parallel)
    uses_gpu = windowed_tss_uses_gpu_replicas(sim)

    if mode == :distributed && !isnothing(sim.pmf)
        throw(ArgumentError("PMF deconvolution is not supported with " *
                "replica_parallel=:distributed yet; run it with :serial or drop the pmf argument"))
    end

    if mode == :threads && uses_gpu
        throw(ArgumentError("replica_parallel=:threads is not supported for GPU-backed " *
                            "TSSSimulation replicas; use :serial or :auto."))
    end

    if mode == :auto
        # GPU replicas go to the workers, one GPU included, as HREMD does; with no worker process
        # to send them to they stay here, where they share the one device as they always have
        uses_gpu && return nprocs() > 1 ? :distributed : :serial
        return (length(sim.replicas) > 1 && n_threads > 1 && Threads.nthreads() > 1) ?
               :threads : :serial
    end
    return mode
end

## Serial
function collect_windowed_tss_observations_serial!(sim::TSSSimulation,
                                                    thread_div,
                                                    initial_step::Int,
                                                    log_initial_state::Bool)
    state = sim.state
    observations = Vector{WindowedTSSObservation}(undef, length(sim.replicas))
    for replica_i in eachindex(sim.replicas)
        observations[replica_i] = collect_windowed_tss_observation!(
            state,
            sim.replicas[replica_i],
            sim.replica_workspaces[replica_i],
            sim.pmf,
            replica_i,
            sim.n_md_steps,
            sim.self_adjustment_steps,
            max(1, thread_div[replica_i]),
            initial_step,
            log_initial_state,
        )
    end
    return observations
end

## Threaded
function collect_windowed_tss_observations_threaded!(sim::TSSSimulation,
                                                      thread_div,
                                                      initial_step::Int,
                                                      log_initial_state::Bool)
    state = sim.state
    observations = Vector{WindowedTSSObservation}(undef, length(sim.replicas))
    @sync for replica_i in eachindex(sim.replicas)
        Threads.@spawn begin
            observations[replica_i] = collect_windowed_tss_observation!(
                state,
                sim.replicas[replica_i],
                sim.replica_workspaces[replica_i],
                sim.pmf,
                replica_i,
                sim.n_md_steps,
                sim.self_adjustment_steps,
                max(1, thread_div[replica_i]),
                initial_step,
                log_initial_state,
            )
        end
    end
    return observations
end

## Distributed
tss_estimator_spec(state::TSSState, window::Integer) =
    (; window = Int(window),
       state_indices = copy(state.estimators[window].state_indices),
       evaluation_state_indices = copy(state.estimators[window].evaluation_state_indices),
       gamma = copy(state.estimators[window].gamma),
       ETA = state.estimators[window].ETA,
       dens_reg = state.estimators[window].dens_reg,
       adaptive_gamma = state.estimators[window].adaptive_gamma)

struct TSSWorkerBlock{SP, AS, W}
    space::SP
    active_state::AS
    workspace::W
    estimators::Dict{Int, Any}
end

const tss_worker_block = Ref{Any}(nothing)

function setup_tss_worker!(space, specs, gpu_id, ::Type{AT}) where AT
    # Host arrays are allowed, so that the worker path can be checked without a GPU
    set_gpu_device!(gpu_id, Val(AT <: AbstractGPUArray))
    states = findall(!isnothing, space.partition.λ_systems)
    local_space = localize_state_space(space, states, AT)
    active_state = ActiveThermoState(local_space, first(states))
    estimators = Dict{Int, Any}(spec.window => make_tss_local_estimator(
            local_space,
            active_state;
            state_indices = spec.state_indices,
            evaluation_state_indices = spec.evaluation_state_indices,
            gamma = spec.gamma,
            ETA = spec.ETA,
            dens_reg = spec.dens_reg,
            history_forgetting = nothing,
            adaptive_gamma = spec.adaptive_gamma,
            require_active_state = false,
        ) for spec in specs)
    workspace = WindowedTSSReplicaWorkspace(collect(values(estimators)), local_space.partition)
    tss_worker_block[] = TSSWorkerBlock(local_space, active_state, workspace, estimators)
    return nothing
end

const tss_workers_key = Ref{Any}(nothing)

function setup_tss_workers(gpu_devices, sim::TSSSimulation, ::Type{AT}) where AT
    state = sim.state
    devices = collect(gpu_devices)
    if nworkers() < length(devices)
        throw(ArgumentError("a multi-GPU TSSSimulation uses one Distributed.jl worker process " *
                "per GPU, but there are $(nworkers()) workers and $(length(devices)) GPUs in " *
                "gpu_devices; add workers with addprocs, load Molly and the GPU package on them " *
                "with @everywhere, and choose the GPUs with the gpu_devices keyword argument"))
    end
    if length(devices) > length(sim.replicas)
        @warn "there are more GPUs ($(length(devices))) than replicas " *
              "($(length(sim.replicas))), so some GPUs will be idle"
        devices = devices[1:length(sim.replicas)]
    end
    # The first worker per GPU, so a session with spare workers can still be used
    pids = workers()[1:length(devices)]

    key = (WeakRef(state), devices, pids, AT)
    cached = tss_workers_key[]
    if !isnothing(cached) && cached[1].value === state && cached[2:4] == key[2:4]
        return pids
    end

    # Every worker holds every window, so any replica can run on any worker. Localized on the host
    # first so that only the evaluation states cross the wire, and once because all workers get it
    specs = [tss_estimator_spec(state, w) for w in eachindex(state.windows)]
    states = sort!(unique!(reduce(vcat,
                    [window.evaluation_state_indices for window in state.windows])))
    host_space = localize_state_space(state.state_space, states, Array)
    @sync for (i, pid) in pairs(pids)
        @async begin
            remotecall_fetch(setup_tss_worker!, pid, host_space, specs, devices[i], AT)
            @info "Worker $(pid) on device $(devices[i]): $(length(state.windows)) windows, " *
                  "$(length(states)) of $(n_states(state.state_space)) states"
            flush(stdout)
        end
    end
    tss_workers_key[] = key
    return pids
end

function run_tss_worker_cycles(requests)
    block = tss_worker_block[]
    isnothing(block) && error("the TSS worker block is not set up on worker $(myid())")
    space = block.space
    AT = array_type(block.active_state.active_sys)
    results = Dict{Int, Any}()

    for request in requests
        estimator = block.estimators[request.window]
        estimator.f .= request.f
        estimator.log_dens .= request.log_dens
        estimator.iteration = request.iteration

        set_active_state!(block.active_state, space, request.state_idx)
        # A new wrapper rather than an assignment, since the loggers are part of the system's type
        active_sys = System(block.active_state.active_sys;
            coords     = to_device(request.coords, AT),
            velocities = to_device(request.velocities, AT),
            boundary   = request.boundary,
            loggers    = map(worker_logger, request.loggers),
        )
        active_state = ActiveThermoState(request.state_idx, active_sys,
                                         block.active_state.active_integrator)
        replica = WindowedTSSReplica(active_state, request.window, request.sample_loggers)
        block.workspace.rng = request.rng

        observation = run_tss_cycle!(replica, block.workspace, estimator, space, nothing,
                                     request.replica_index, request.n_md_steps,
                                     request.self_adjustment_steps, 1, request.initial_step,
                                     request.log_initial_state, request.window_offset)

        results[request.replica_index] = (
            next_state     = active_state.active_idx,
            coords         = from_device(active_sys.coords),
            velocities     = from_device(active_sys.velocities),
            boundary       = active_sys.boundary,
            rng            = block.workspace.rng,
            loggers        = active_sys.loggers,
            sample_loggers = replica.sample_loggers,
            observation    = observation,
        )
    end
    return results
end


function collect_windowed_tss_observations_distributed!(sim::TSSSimulation,
                                                        pids,
                                                        initial_step::Int,
                                                        log_initial_state::Bool)
    state = sim.state
    requests = [Any[] for _ in eachindex(pids)]
    for (replica_i, replica) in pairs(sim.replicas)
        estimator = state.estimators[replica.active_window]
        active_sys = replica.active_state.active_sys
        # Replicas are dealt out round robin, which is an even split however they move
        push!(requests[mod1(replica_i, length(pids))], (
            replica_index         = replica_i,
            window                = replica.active_window,
            state_idx             = replica.active_state.active_idx,
            coords                = from_device(active_sys.coords),
            velocities            = from_device(active_sys.velocities),
            boundary              = active_sys.boundary,
            f                     = copy(estimator.f),
            log_dens              = copy(estimator.log_dens),
            iteration             = estimator.iteration,
            window_offset         = windowed_tss_window_offset(state, replica.active_window),
            rng                   = sim.replica_workspaces[replica_i].rng,
            loggers               = active_sys.loggers,
            sample_loggers        = replica.sample_loggers,
            n_md_steps            = sim.n_md_steps,
            self_adjustment_steps = sim.self_adjustment_steps,
            initial_step          = initial_step,
            log_initial_state     = log_initial_state,
        ))
    end

    futures = [remotecall(run_tss_worker_cycles, pids[i], requests[i]) for i in eachindex(pids)]
    results = Base.merge(map(fetch, futures)...)

    observations = Vector{WindowedTSSObservation}(undef, length(sim.replicas))
    for replica_i in eachindex(sim.replicas)
        result = results[replica_i]
        replica = sim.replicas[replica_i]
        active_sys = replica.active_state.active_sys
        # The results come back on host arrays whatever the state is on, and a broadcast of a host
        # vector into a device array is not a valid kernel
        copyto!(active_sys.coords, result.coords)
        copyto!(active_sys.velocities, result.velocities)
        active_sys.boundary = result.boundary
        active_sys.loggers = result.loggers
        set_active_state!(replica.active_state, state.state_space, result.next_state)
        replica.sample_loggers = result.sample_loggers
        sim.replica_workspaces[replica_i].rng = result.rng
        observations[replica_i] = result.observation
    end
    push!(state.stats.worker_occupancy, map(length, requests))
    return observations
end

function sync_windowed_tss_state_to_replica!(state::TSSState,
                                              replica::WindowedTSSReplica)
    state.active_window = replica.active_window
    if state.active_state !== replica.active_state
        set_active_state!(
            state.active_state,
            state.state_space,
            replica.active_state.active_idx,
        )
        state.active_state.active_sys.coords .= replica.active_state.active_sys.coords
        state.active_state.active_sys.velocities .= replica.active_state.active_sys.velocities
        state.active_state.active_sys.boundary = replica.active_state.active_sys.boundary
    end
    return state
end

# The window each replica runs the coming cycle in. Drawn on the host, from the replica's own RNG
# and in replica order, so that the multi-GPU path knows where to send each replica before the
# cycle starts and the RNG streams stay the same as in a serial run
function choose_windowed_tss_cycle_windows!(sim::TSSSimulation)
    state = sim.state
    for (replica_i, replica) in pairs(sim.replicas)
        check_windowed_tss_replica_invariant(state, replica)
        replica.active_window = other_window_for_state(
            state,
            replica.active_window,
            replica.active_state.active_idx;
            rng = sim.replica_workspaces[replica_i].rng,
        )
    end
    return sim
end

function simulate!(sim::TSSSimulation;
                   rng = Random.default_rng(),
                   n_threads::Integer = Threads.nthreads(),
                   replica_rngs = nothing,
                   replica_parallel = :auto,
                   show_progress = default_show_progress(),
                   gpu_devices = nothing)
    state::TSSState = sim.state
    n_threads > 0 || throw(ArgumentError("n_threads must be positive."))
    if length(sim.replica_workspaces) != length(sim.replicas)
        throw(ArgumentError("TSSSimulation replica workspaces do not match replicas."))
    end

    parallel_mode = resolve_tss_replica_parallel(sim, replica_parallel, Int(n_threads))
    thread_div = equal_parts(Int(n_threads), length(sim.replicas))
    worker_pids = nothing
    if parallel_mode == :distributed
        # Every GPU by default, but no more of them than there are workers to drive them
        devices = isnothing(gpu_devices) ?
                  get_gpu_devices(Val(true))[1:min(end, nworkers())] : gpu_devices
        worker_pids = setup_tss_workers(devices, sim,
                            array_type(sim.replicas[1].active_state.active_sys))
    end

    if isnothing(replica_rngs)
        seed_windowed_tss_replica_rngs!(sim, rng)
    else
        seed_windowed_tss_replica_rngs!(sim, replica_rngs)
    end

    progress = setup_progress(sim.n_cycles, show_progress)
    for cycle in 1:sim.n_cycles
        cycle_start_step = sim.current_step
        log_initial_state = sim.initial_log_pending
        choose_windowed_tss_cycle_windows!(sim)
        observations = if parallel_mode == :distributed
            collect_windowed_tss_observations_distributed!(
                sim,
                worker_pids,
                cycle_start_step,
                log_initial_state,
            )
        elseif parallel_mode == :threads
            collect_windowed_tss_observations_threaded!(
                sim,
                thread_div,
                cycle_start_step,
                log_initial_state,
            )
        else
            collect_windowed_tss_observations_serial!(
                sim,
                thread_div,
                cycle_start_step,
                log_initial_state,
            )
        end
        history_time = state.iteration + 1
        accumulate_tss_pmf_deconvolution!(
            sim.pmf,
            state,
            observations;
            history_time = history_time,
        )
        max_delta_f = sim.frozen ?
                      apply_windowed_tss_frozen_observations!(state, observations) :
                      apply_windowed_tss_observations!(state, observations)
        sim.frozen || drop_old_tss_pmf_deconvolution_epochs!(sim.pmf, state, state.iteration)
        sync_windowed_tss_state_to_replica!(state, first(sim.replicas))

        if !sim.frozen && should_log_tss(state.iteration, sim.log_freq)
            for observation in observations
                estimator = state.estimators[observation.update_window]
                log_tss_stats!(
                    estimator.stats,
                    estimator,
                    observation.visited_state,
                    observation.sampled_next_state,
                    max_delta_f,
                )
            end
            first_observation = first(observations)
            log_windowed_tss_stats!(
                state.stats,
                state,
                first_observation.update_window,
                first_observation.visited_state,
                first_observation.sampled_next_state,
                max_delta_f;
                replica_indices = [observation.replica_index for observation in observations],
                replica_update_windows = [observation.update_window for observation in observations],
                replica_visited_states = [observation.visited_state for observation in observations],
                replica_sampled_next_states = [observation.sampled_next_state for observation in observations],
                replica_max_abs_delta_f = fill(max_delta_f, length(observations)),
            )

        end
        sim.current_step += sim.self_adjustment_steps * sim.n_md_steps
        sim.initial_log_pending = false
        next_nograd!(progress)
    end

    return state
end
