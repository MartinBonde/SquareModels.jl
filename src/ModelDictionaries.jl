# ModelDictionaries — variable-to-value mappings for JuMP models
#
# This file defines [`ModelDictionary`](@ref), [`load`](@ref), [`unload`](@ref), and
# helpers for reading tabular data into JuMP variable containers. Included by
# SquareModels; exported from the main module.

using Dictionaries
using Parquet2
using DataFrames
using CSV

"""
    ModelDictionary

A dictionary mapping JuMP variable names to numeric values.

`ModelDictionary` is the primary container for model data in SquareModels: calibration
inputs, solved values, and scenario comparisons. Values are keyed by JuMP's internal
variable names (e.g. `"K[2025]"`, `"σ"`).

# Access patterns
- **Scalar:** `d[x]`, `d["σ"]`, `d.σ`
- **Container:** `d[y]` returns a [`Window`](@ref) view; `d[y[1:3]]` and `d.y[1:3]` work too
- **Broadcasting:** `d .+ 1`, `d[d .> 0]` (boolean mask returns a subset dictionary)
- **Dot assignment:** `d.y .= [1, 2, 3]`

Unset entries are `nothing`. After adding variables to the model (e.g. via new blocks),
call [`add_missing_model_variables!`](@ref) or index the dictionary to sync new keys.

# Fields
- `model::AbstractModel`: The JuMP model whose variables are tracked
- `dictionary`: Typed values with shared, immutable name indices

# Examples
```julia
model = Model()
@variable(model, x)
@variable(model, y[1:3])

d = ModelDictionary(model)

# Set values using different access methods
d[x] = 1.0
d["y"] = [1, 2, 3]    # String access
d.y = [1, 2, 3]       # Dot notation

# Get values
d[x]       # 1.0
d.y[1]     # 1

# Save / load round-trip
unload("data.parquet", d)
d2 = load("data.parquet", model)
```

See also: [`fix`](@ref), [`set_start_value`](@ref), [`value_dict`](@ref), [`load`](@ref), [`unload`](@ref)
"""
mutable struct ModelDictionary{T,M,L,V<:AbstractVariableRef}
	model::M
	dictionary::Dictionary{String,Union{Nothing,T}}
	_layout::L
	_revision::UInt
	_full::Bool
	_variables::Vector{V}
	_variable_positions::Union{Nothing,Dict{MOI.VariableIndex,Int}}
end

include("ModelDictionaryStorage.jl")
Base.keys(d::ModelDictionary) = (_ensure_data_snapshot!(d); keys(d.dictionary))
Base.values(d::ModelDictionary) = (_ensure_data_snapshot!(d); values(d.dictionary))
Base.length(d::ModelDictionary) = (_ensure_data_snapshot!(d); length(d.dictionary))
Base.eltype(::Type{<:ModelDictionary{T}}) where {T} = Union{Nothing,T}
Base.isassigned(d::ModelDictionary, args...) = (_ensure_data_snapshot!(d); isassigned(d.dictionary, args...))
Base.haskey(d::ModelDictionary, key) = (_ensure_data_snapshot!(d); haskey(d.dictionary, key))
Base.get(d::ModelDictionary, key, default) = (_ensure_data_snapshot!(d); get(d.dictionary, key, default))
Base.filter(f, d::ModelDictionary) = (_ensure_data_snapshot!(d); filter(f, d.dictionary))
function Base.iterate(d::ModelDictionary)
	_ensure_data_snapshot!(d)
	result = iterate(d.dictionary)
	result === nothing && return nothing
	value, state = result
	return value, (d.dictionary, state)
end
function Base.iterate(::ModelDictionary, (dictionary, state))
	result = iterate(dictionary, state)
	result === nothing && return nothing
	value, next_state = result
	return value, (dictionary, next_state)
end

function Base.show(io::IO, md::ModelDictionary)
	n = length(md)
	print(io, "ModelDictionary with $n entries")
	n == 0 && return
	assigned = count(!isnothing, values(md.dictionary))
	print(io, " ($assigned assigned, $(n - assigned) unset)")
end

Base.show(io::IO, ::MIME"text/plain", md::ModelDictionary) = show(io, md)

"""
    ModelDictionary(model::AbstractModel)

Create a dictionary mapping all variables in `model` to values (initially `nothing`).

Supports convenient syntax for getting/setting values using variable references,
symbols, or dot notation.

# Arguments
- `model::AbstractModel`: The JuMP model whose variables to track

# Returns
A `ModelDictionary` with all model variables initialized to `nothing`.

# Examples
```julia
model = Model()
@variable(model, x)
@variable(model, y[1:3])

d = ModelDictionary(model)
d[x] = 1.0
d.y = [1, 2, 3]  # Dot notation

fix(d)  # Fix all variables to their values in d
```

See also: [`fix`](@ref), [`set_start_value`](@ref), [`value_dict`](@ref)
"""
ModelDictionary(m::AbstractModel) = ModelDictionary{Float64}(m)

"""
    ModelDictionary(model::AbstractModel, values::Union{Number, AbstractVector})

Create a dictionary with all variables set to the provided values.

# Arguments
- `model::AbstractModel`: The JuMP model whose variables to track
- `values`: A single number (applied to all) or vector of values

# Returns
A `ModelDictionary` with variables initialized to the given values.
"""
function ModelDictionary(m::AbstractModel, values::Union{Number, AbstractVector})
	d = ModelDictionary(m)
	_set_initial_values!(d, values)
	return d
end

function Base.copy(md::ModelDictionary)
	_ensure_data_layout!(md)
	return _derived_dictionary(md, copy(md.dictionary.values))
end

"""
    add_missing_model_variables!(md::ModelDictionary)

Add any JuMP model variables that are not yet in the dictionary.

This is useful after defining new blocks (which create residual variables)
to ensure the dictionary includes all model variables.

New variables are initialized to `nothing`.
"""
function add_missing_model_variables!(md::ModelDictionary)
	_ensure_data_layout!(md; expand=true)
	return md
end

function Base.setindex!(d::ModelDictionary, value, index::String)
	_ensure_data_layout!(d)
	found, token = gettoken(keys(d.dictionary), index)
	if found
		settokenvalue!(d.dictionary, token, convert(eltype(d.dictionary), value))
		return value
	end
	sym = Symbol(index)
	haskey(d.model, sym) && return setindex!(d, value, d.model[sym])
	throw(KeyError(index))
end
function Base.setindex!(d::ModelDictionary, value, index::AbstractVariableRef)
	_ensure_data_layout!(d)
	d.dictionary.values[_variable_position(d, index)] = value
	return value
end
Base.setindex!(d::ModelDictionary, value, index::Symbol) = setindex!(d, value, String(index))
function Base.setindex!(d::ModelDictionary, value, index::AbstractArray)
	_set_window!(d[index], value)
	return value
end

function Base.getindex(d::ModelDictionary, index::String)
	_ensure_data_layout!(d)
	found, token = gettoken(keys(d.dictionary), index)
	found && return gettokenvalue(d.dictionary, token)
	sym = Symbol(index)
	haskey(d.model, sym) && return getindex(d, d.model[sym])
	throw(KeyError(index))
end
function Base.getindex(d::ModelDictionary, index::AbstractVariableRef)
	_ensure_data_layout!(d)
	return d.dictionary.values[_variable_position(d, index)]
end
Base.getindex(d::ModelDictionary, index::Symbol) = getindex(d, String(index))
function Base.getindex(d::ModelDictionary, container::AbstractArray{<:AbstractString}, varname::Union{Nothing, AbstractString}=nothing)
	return d[_container_selection(d, container, varname)]
end
function Base.getindex(d::ModelDictionary, container::AbstractArray)
	return d[_container_selection(d, container)]
end

# Filtering with a boolean ModelDictionary (e.g., d[d .> 0])
function Base.getindex(d::ModelDictionary, mask::ModelDictionary)
	_ensure_data_layout!(d)
	_ensure_data_layout!(mask)
	_assert_aligned(d, mask)
	selected = findall(x -> x === true, mask.dictionary.values)
	return _subset_dictionary(d, selected)
end


"""
    Window{T, S}

A view into a subset of a `ModelDictionary`, indexed like a JuMP variable container.

`Window` provides array-like access to a slice of a `ModelDictionary` that corresponds
to an indexed JuMP variable (e.g., `y[1:3]`). It allows reading and writing values
using the same indices as the original variable.

This is an internal type typically created automatically when indexing a
`ModelDictionary` with a variable container.

# Fields
- `data_view::T`: View into the underlying dictionary values
- `indices::S`: Index mapping matching the variable container's axes

# Examples
```julia
model = Model()
@variable(model, y[1:3])

d = ModelDictionary(model)
d.y = [10, 20, 30]

w = d[y]     # Returns a Window
w[1]         # 10
w[2] = 25    # Modify through the window
d[y[2]]      # 25
```
"""
struct Window{T, S} <: AbstractSeries
	data_view::T
	indices::S
	varname::Union{Nothing, AbstractString}
end
function create_window(data_view, container, varname::Union{Nothing, AbstractString}=nothing)
	indices = (_->0).(container)
	for (i, idx) in enumerate(eachindex(indices))
		indices[idx] = i
	end
	Window(data_view, indices, varname)
end
function create_window(data_view, container::DenseAxisArray, varname::Union{Nothing, AbstractString}=nothing)
	# Broadcasting a DenseAxisArray shares its axes and lookup tables. Prepared
	# selections need independent coordinates even if the source labels change.
	positions = reshape(collect(1:length(container)), size(container.data))
	indices = DenseAxisArray(positions, map(copy, axes(container))...; names=container.names)
	return Window(data_view, indices, varname)
end
function create_window(data_view, container::SparseZeroArray, varname::Union{Nothing, AbstractString}=nothing)
	indices = similar(container, Int)
	for (i, key) in enumerate(keys(container))
		indices[key] = i
	end
	return Window(data_view, indices, varname)
end

function Base.getproperty(w::Window, name::Symbol)
	# Public views may be saved for later evaluation, so retain their storage
	# checks. Bulk operations unwrap the values after validating the view.
	name == :shaped_view && return reshape(w.data_view, size(w.indices))
	return getfield(w, name)
end

@forward Window.indices (
	Base.length,
	Base.size,
	Base.axes,
	Base.ndims,
	Base.keys,
	Base.lastindex,
)
Base.collect(w::Window) = collect(reshape(_window_storage(w), size(w.indices)))
# Keep the validated storage in the iteration state, avoiding a model-layout
# check for every cell during a traversal. Iteration order is flat for both
# dense and sparse windows; collect retains the dense window's shape.
function _iterate_window(storage, state...)
	next = iterate(storage, state...)
	isnothing(next) && return nothing
	value, next_state = next
	return value, (storage, next_state)
end
Base.iterate(w::Window) = _iterate_window(_window_storage(w))
Base.iterate(::Window, state::Tuple) = _iterate_window(state[1], state[2])
Base.collect(w::Window{<:Any,<:_SparseTableArray}) = collect(_window_storage(w))

_table_layout(w::Window) = _table_layout(w.shaped_view, axes(w.indices))
function _table_layout(w::Window{<:Any,<:_SparseTableArray})
	storage = _window_storage(w)
	sparse = _sparse_axis_array(w.indices)
	keys = collect(Base.keys(sparse.data))
	values = [storage[w.indices[key...]] for key in keys]
	return _sparse_table_layout(keys, values)
end

_window_size_label(w::Window{<:Any,<:_SparseTableArray}) = "$(length(w))-element"
function _window_size_label(w::Window)
	sizes = length.(axes(w.indices))
	return length(sizes) == 1 ? "$(only(sizes))-element" : join(sizes, "×")
end

function Base.show(io::IO, ::MIME"text/plain", w::Window)
	n = length(w)
	print(io, _window_size_label(w), " Window")
	n == 0 && return
	println(io, ":")
	_period_row_table(io, _table_layout(w), something(w.varname, ""))
end
Base.show(io::IO, w::Window) = show(io, MIME"text/plain"(), w)

Base.getindex(w::Window, index::AbstractArray) = length(index) == 1 ? getindex(w, index[]) : getindex.(Ref(w), index)
_window_slice(w::Window, index::Integer) = w.data_view[index]
# A Window holds data, not an expression, so an unstored cell reads as no
# observation. `Zero()` is only the additive identity for equation building.
_window_slice(w::Window, ::Zero) = (_window_storage(w); nothing)
function _window_slice(w::Window, indices::AbstractArray)
	storage = _window_storage(w)
	return map(i -> storage[i], Array(indices))
end
function _window_slice(w::Window, indices::SparseAxisArray)
	storage = _window_storage(w)
	values = similar(indices, eltype(storage))
	for key in keys(indices.data)
		values[key] = storage[indices[key]]
	end
	return values
end
_window_slice(w::Window, indices::SparseZeroArray) =
	SparseZeroArray(_window_slice(w, indices.data), map(copy, indices.domain))

Base.getindex(w::Window, indices...) = _window_slice(w, w.indices[indices...])

Base.setindex!(w::Window, value, index::AbstractArray) = setindex!.(Ref(w), value, index)
Base.setindex!(w::Window, value, indices...) = setindex!.(Ref(_window_storage(w)), value, w.indices[indices...])

# Additional array methods for Window
Base.vec(w::Window) = vec(collect(w))

# Broadcasting support for Window - use shaped_view as the broadcastable representation
Base.broadcastable(w::Window{<:Any,<:_SparseTableArray}) = _window_slice(w, w.indices)
Base.broadcastable(w::Window) = w.shaped_view

# For broadcast assignment (w .= x), write into the underlying data.
# Keyed sparse sources align by index tuple. An unstored source key is `nothing`.
_window_keys(indices::SparseAxisArray) = keys(indices.data)
_window_keys(indices::SparseZeroArray) = eachindex(indices)
_window_keys(indices) = keys(indices)

# Read one coordinate of a keyed source. A key the source does not store has no observation.
_source_at(kd::KeyedData, key::Tuple) = get(kd.data, key, nothing)
_source_at(s::SparseAxisArray, key::Tuple) = get(s.data, key, nothing)

_set_window!(w::Window, source::SparseZeroArray) = _set_window!(w, source.data)
_set_window!(w::Window, source::SparseAxisArray) = _assign_keyed_source!(w, source)
_set_window!(w::Window, source::KeyedData) = _assign_keyed_source!(w, source)
# Dense labelled inputs are positional, like ordinary arrays. Their numeric
# buffer has ordinary axes and supports flattening without interpreting labels.
_set_window!(w::Window, source::DenseAxisArray) = _set_window!(w, source.data)
# JuMP eagerly evaluates DenseAxisArray broadcasts, so dotted assignment can
# receive the labelled array itself instead of a Broadcasted expression.
Base.materialize!(w::Window, source::DenseAxisArray) = _set_window!(w, source)
function _set_window!(w::Window, source::AbstractArray)
	storage = _window_storage(w)
	storage .= _window_unalias_arg(storage, vec(source))
	return w
end
function _set_window!(w::Window, value)
	storage = _window_storage(w)
	storage .= value
	return w
end
function _set_window!(w::Window, value::Union{Number,Nothing})
	fill!(_window_storage(w), value)
	return w
end
_set_window!(w::Window, source::Window) = _set_window!(w, Base.broadcastable(source))

function _assign_keyed_source!(w::Window, source)
	storage = _window_storage(w)
	target_rank = ndims(w.indices)
	source_rank = ndims(source)
	source_rank == target_rank || throw(DimensionMismatch(
		"Cannot assign sparse data with $source_rank index axes to a window with $target_rank index axes",
	))
	for key in _window_keys(w.indices)
		idx = _index_tuple(key)
		storage[w.indices[idx...]] = _source_at(source, idx)
	end
	return w
end

# A window can contain repeated storage positions. Even an identical source view
# must be snapshotted when it aliases the destination: otherwise `w .= w .+ 1`
# increments a repeated cell twice. Nonaliasing sources need no intermediate.
_window_unalias_arg(destination, arg) = arg
function _window_unalias_arg(destination, arg::AbstractArray)
	storage = _uncheck_model_array(arg)
	return Base.mightalias(destination, storage) ? copy(storage) : storage
end
function _window_unalias_arg(destination, bc::Base.Broadcast.Broadcasted{Style}) where {Style}
	args = map(arg -> _window_unalias_arg(destination, arg), bc.args)
	return Base.Broadcast.Broadcasted{Style}(bc.f, args, bc.axes)
end

# Array sources are assigned in linear order, independently of the window's
# labelled shape. Matching the destination shape to the broadcast result lets
# Base fuse the expression.
function Base.materialize!(w::Window, bc::Base.Broadcast.Broadcasted{<:Base.Broadcast.DefaultArrayStyle})
	storage = _window_storage(w)
	instantiated = Base.Broadcast.instantiate(bc)
	shape = map(length, axes(instantiated))
	n = prod(shape)
	if n == 1
		value = instantiated[CartesianIndex(map(_ -> 1, shape))]
		isempty(shape) && return _set_window!(w, value)
		fill!(storage, value)
		return w
	end
	n == length(storage) || throw(DimensionMismatch(
		"Cannot assign $n values to a window with $(length(storage)) cells",
	))
	safe = _window_unalias_arg(storage, instantiated)
	destination = length(shape) == 1 ? storage : reshape(storage, shape)
	copyto!(destination, safe)
	return w
end

# Custom sparse styles retain their key alignment and zero-preserving rules.
# A direct keyed assignment can reuse its source without copying its cells.
function Base.materialize!(w::Window, bc::Base.Broadcast.Broadcasted{Style}) where {Style}
	if bc.f === identity && length(bc.args) == 1
		source = only(bc.args)
		if source isa Union{SparseZeroArray,SparseAxisArray,DenseAxisArray}
			return _set_window!(w, source)
		end
	end
	return _set_window!(w, Base.materialize(bc))
end

Base.in(index::String, d::ModelDictionary) = haskey(d, index)
Base.in(index::Symbol, d::ModelDictionary) = String(index) ∈ d
function Base.in(index::AbstractVariableRef, d::ModelDictionary)
	_ensure_data_snapshot!(d)
	JuMP.owner_model(index) === d.model || return false
	positions = d._full ? d._layout.id_to_slot : d._variable_positions
	return haskey(positions, JuMP.index(index))
end
Base.in(index::AbstractArray, d::ModelDictionary) = all(v -> v in d, index)

function Base.replace!(d::ModelDictionary, old_new::Pair...)
	for (k, v) in zip(keys(d), replace(collect(d), old_new...))
		d[k] = v
	end
	return d
end

function Base.replace(d::ModelDictionary, old_new::Pair...)
	d2 = copy(d)
	return replace!(d2, old_new...)
end

# ----------------------------------------------------------------------------------------------------------------------
# JuMP extensions for ModelDictionary
# ----------------------------------------------------------------------------------------------------------------------
"""
    fix(var::AbstractVariableRef, d::ModelDictionary)

Fix a single variable to its value in the dictionary.

# Arguments
- `var::AbstractVariableRef`: The variable to fix
- `d::ModelDictionary`: Dictionary containing the target value

# Examples
```julia
d = ModelDictionary(model)
d[x] = 5.0
fix(x, d)  # Fix x to 5.0.
```

See also: [`ModelDictionary`](@ref), [`set_start_value`](@ref)
"""
JuMP.fix(var::AbstractVariableRef, d::ModelDictionary) = fix(var, d[var], force=true)

"""
    fix(variables::AbstractArray, d::ModelDictionary)

Fix a collection of variables to their values in the dictionary.

# Arguments
- `variables::AbstractArray`: Array of variable references
- `d::ModelDictionary`: Dictionary containing the target values
"""
JuMP.fix(variables::AbstractArray, d::ModelDictionary) = fix.(variables, Ref(d))

"""
    fix(model::AbstractModel, d::ModelDictionary)
    fix(d::ModelDictionary)

Fix variables to their values in a `ModelDictionary`.

`fix(d)` synchronizes the dictionary before fixing its variables by identity.
A full dictionary includes newly added model variables, and each must have a
non-`nothing` value. A subset dictionary (e.g. from `d[d .> 0]`) fixes only its
selected variables. `fix(model, d)` requires values for every model variable.

# Arguments
- `model::AbstractModel`: The model whose variables to fix (optional if using `fix(d)`)
- `d::ModelDictionary`: Dictionary containing the target values

# Examples
```julia
model = Model()
@variable(model, x)
@variable(model, y[1:3])

d = ModelDictionary(model)
d[x] = 1.0
d.y = [1, 2, 3]

fix(d)  # Fix all variables to their values in d
# Equivalent to: fix(model, d)

# Fix only a subset
fix(d[d .> 0])
```

See also: [`ModelDictionary`](@ref), [`set_start_value`](@ref), [`value_dict`](@ref)
"""
function JuMP.fix(model::AbstractModel, d::ModelDictionary)
	for var in all_variables(model)
		v = d[var]
		isnothing(v) && error("Cannot fix variable $(name(var)): no value in dictionary. Set it explicitly (e.g., to 0) before fixing.")
		fix(var, v, force=true)
	end
end
function JuMP.fix(d::ModelDictionary)
	_ensure_data_layout!(d)
	for (var, v) in zip(d._variables, d.dictionary.values)
		isnothing(v) && error("Cannot fix variable $(name(var)): no value in dictionary. Set it explicitly (e.g., to 0) before fixing.")
		fix(var, v, force=true)
	end
end

"""
    set_start_value(var::AbstractVariableRef, d::ModelDictionary)

Set the starting value of a variable from a ModelDictionary.

# Arguments
- `var::AbstractVariableRef`: The variable to set the start value for
- `d::ModelDictionary`: Dictionary containing the start value

See also: [`ModelDictionary`](@ref), [`fix`](@ref)
"""
JuMP.set_start_value(var::AbstractVariableRef, values::ModelDictionary) = set_start_value(var, values[var]::Number)

"""
    set_start_value(variables::AbstractArray, d::ModelDictionary)

Set the starting values of a collection of variables from a ModelDictionary.

# Arguments
- `variables::AbstractArray`: Array of variable references
- `d::ModelDictionary`: Dictionary containing the start values
"""
JuMP.set_start_value(variables::AbstractArray, values::ModelDictionary) = set_start_value.(variables, Ref(values))

"""
    set_start_value(model::AbstractModel, d::ModelDictionary)
    set_start_value(d::ModelDictionary)

Set starting values for variables from a `ModelDictionary`.

Behavior matches [`fix`](@ref): a full dictionary requires every model variable to
have a value; a subset dictionary only sets start values for keys present in `d`.

# Arguments
- `model::AbstractModel`: The model whose variables to set (optional if using `set_start_value(d)`)
- `d::ModelDictionary`: Dictionary containing the start values

# Examples
```julia
model = Model()
@variable(model, x)
@variable(model, y[1:3])

d = ModelDictionary(model)
d[x] = 1.0
d.y = [1, 2, 3]

set_start_value(d)  # Set start values for all variables
```

See also: [`ModelDictionary`](@ref), [`fix`](@ref), [`value_dict`](@ref), [`load`](@ref)
"""
function JuMP.set_start_value(model::AbstractModel, d::ModelDictionary)
	for var in all_variables(model)
		v = d[var]
		isnothing(v) && error("Cannot set start value for $(name(var)): no value in dictionary. Set it explicitly before calling set_start_value.")
		set_start_value(var, v)
	end
end
function JuMP.set_start_value(d::ModelDictionary)
	_ensure_data_layout!(d)
	for (var, v) in zip(d._variables, d.dictionary.values)
		isnothing(v) && error("Cannot set start value for $(name(var)): no value in dictionary. Set it explicitly before calling set_start_value.")
		set_start_value(var, v)
	end
end

"""
    value_dict(model::AbstractModel) → ModelDictionary

Extract the solution values of all variables as a ModelDictionary.

Call this after `optimize!(model)` to capture the solution in a dictionary
that can be used for warm-starting, comparing solutions, or fixing variables.

# Arguments
- `model::AbstractModel`: A solved JuMP model

# Returns
A `ModelDictionary` containing the optimal value of each variable.

# Examples
```julia
model = Model(Ipopt.Optimizer)
@variable(model, x >= 0)
@variable(model, y >= 0)
@constraint(model, x + y == 10)
@objective(model, Max, x + 2y)

optimize!(model)

d = value_dict(model)
d[x]  # Optimal value of x
d[y]  # Optimal value of y

# Use solution as starting point for another solve
set_start_value(d)
```

See also: [`ModelDictionary`](@ref), [`fix`](@ref), [`set_start_value`](@ref)
"""
value_dict(model::AbstractModel) = ModelDictionary(model, value.(all_variables(model)))

# ----------------------------------------------------------------------------------------------------------------------
# Parquet serialization
# ----------------------------------------------------------------------------------------------------------------------
"""
    parse_variable_name(name::String) → (base_name, indices)

Parse a JuMP variable name into its base name and index string.

# Examples
```julia
parse_variable_name("K[2025]")       # ("K", "2025")
parse_variable_name("cᵃ[15,2025]")   # ("cᵃ", "15,2025")
parse_variable_name("σˣ")            # ("σˣ", "")
```
"""
function parse_variable_name(name::String)
	m = match(r"^(.+?)\[(.+)\]$", name)
	isnothing(m) && return (name, "")
	return (m.captures[1], m.captures[2])
end

"""
    unload(path::AbstractString, d::ModelDictionary)

Save a `ModelDictionary` to a Parquet file in the **simple format**.

Each assigned entry becomes one row. Entries with `nothing` values are omitted.
Storage is synchronized before export. After renaming or deleting model variables,
call [`refresh_model_layout!`](@ref) first, as for ordinary dictionary access.

| Column     | Description |
|------------|-------------|
| `variable` | Base name (e.g. `"K"`, `"cᵃ"`) |
| `indices`  | Comma-joined index string (`"2025"`, `"15,2025"`, or `""` for scalars) |
| `value`    | Numeric value |

This format is also accepted by [`load`](@ref) for Parquet and CSV files, and by
[`read_variable`](@ref), [`read_sparse_array`](@ref), and [`read_indices`](@ref).

# Arguments
- `path`: Output path (`.parquet`)
- `d`: The `ModelDictionary` to save

# Examples
```julia
d = value_dict(model)
unload("solution.parquet", d)
```

See also: [`load`](@ref), [`ModelDictionary`](@ref)
"""
function unload(path::AbstractString, d::ModelDictionary)
	_ensure_data_layout!(d)
	rows = NamedTuple{(:variable, :indices, :value), Tuple{String, String, Float64}}[]
	for (k, v) in pairs(d.dictionary)
		isnothing(v) && continue
		base, indices = parse_variable_name(k)
		push!(rows, (; variable=base, indices=indices, value=Float64(v)))
	end
	Parquet2.writefile(path, DataFrame(rows))
end

"""
    load(path::AbstractString, model::AbstractModel; renames...) → ModelDictionary
    load(path::AbstractString, model::AbstractModel, renames::Pair...) → ModelDictionary

Load a `ModelDictionary` from a Parquet, CSV, or GDX file.

Walks every variable in `model` and looks up `(base_name, indices)` in the file.
Unmatched model variables remain `nothing`. Data rows whose indices fall outside the
model's index sets are ignored (no error).

# Supported formats

**Simple format** (Parquet and CSV): columns `variable`, `indices`, `value` — the
format written by [`unload`](@ref). Integer index components are parsed as `Int`;
other components become `Symbol`.

**Gekko Parquet format**: columns `id`, `name`, `dim1`, `dim2`, `period`, `value`.
Metadata rows carry variable names; data rows carry values. Converted internally to
the simple format.

**GDX** (`.gdx`): requires the optional GDXInterface extension (`using GDXInterface`).
Multi-dimensional GDX parameters use comma-joined indices, as in the simple format.

# Name mappings

Mappings associate a model variable's **base name** with a data symbol. Pass them as
keyword arguments or trailing `Pair`s (`Y => "OtherY"`). Keys may be `Symbol`s or
JuMP variable references; only the base name is used.

**Simple rename** — load `OtherY` data into model variable `Y`:

```julia
load(path, model; Y = "OtherY")
load(path, model, Y => "OtherY", X => "DataX")
```

**Slice** — extract a lower-dimensional slice from a higher-dimensional data symbol.
Use `:` for positions filled from the model variable's indices; fixed labels pin
other dimensions (GAMS-style `vC[:cTot,:]`):

```julia
load(path, model; C = "vC[:cTot,:]")       # C[t] ← vC[:cTot, t]
load(path, model; K = "vK[:iTot,:tot,:]")   # K[t] ← vK[:iTot, :tot, t]
```

A spec without brackets (e.g. `"nPop"`) is a simple rename. A spec with brackets is
always treated as a slice, even if every position is fixed.

# Arguments
- `path`: Path to a `.parquet`, `.csv`, or `.gdx` file
- `model`: JuMP model whose variables define the output dictionary
- `renames`: Optional `ModelVar => data_symbol` mappings (keyword or `Pair` syntax)

# Returns
A `ModelDictionary` for `model` with loaded values; missing entries are `nothing`.

# Examples
```julia
d = load("solution.parquet", model)
set_start_value(d)  # warm-start from file

# Rename data symbols (similar to GAMS \$LOAD path Y=OtherY;)
d = load("data.parquet", model; N_a = "nPop", L_a = "nLHh")

# GDX with renames and slices (after `using GDXInterface`)
d = load("data.gdx", model;
    N_a = "nPop",
    C = "vC[:cTot,:]",
)
```

See also: [`unload`](@ref), [`read_variable`](@ref), [`ModelDictionary`](@ref)
"""
function load(path::AbstractString, model::AbstractModel, renames::Pair...; kwargs...)
	rename_dict, slice_dict = _build_rename_and_slice_dicts(renames, kwargs)

	# Dispatch based on file extension
	ext = lowercase(path)
	if endswith(ext, ".gdx")
		return _load_gdx(path, model, rename_dict, slice_dict)
	elseif endswith(ext, ".csv")
		return _load_csv(path, model, rename_dict, slice_dict)
	else
		return _load_parquet(path, model, rename_dict, slice_dict)
	end
end

"""Load from a GDX file using GDXInterface.jl when the optional extension is loaded."""
function _load_gdx(path, model, rename_dict, slice_dict)
	error("Loading GDX files requires the optional GDXInterface extension. Run `using GDXInterface` before calling `load` on a .gdx file.")
end

"""Normalize a tabular cell to String, treating missing as empty."""
_tab_str(x) = ismissing(x) ? "" : string(x)

const IndexValue = Union{Symbol, Int}

"""Parse one index component from a comma-joined indices string."""
_parse_index_part(s) = (i = tryparse(Int, s)) === nothing ? Symbol(s) : i

"""Parse comma-joined indices from the simple (variable, indices, value) format."""
function _parse_index_tuple(indices::AbstractString)
	isempty(strip(indices)) && error("Empty indices string")
	return Tuple(_parse_index_part(strip(s)) for s in split(indices, ","))
end

"""Extract rows in simple (variable, indices, value) format."""
function _simple_format_df(df::DataFrame)
	("variable" in names(df) && "indices" in names(df)) ||
		error("Expected columns: (variable, indices, value)")
	return df[.!ismissing.(df.value), [:variable, :indices, :value]]
end

function _read_simple_df(path::AbstractString)
	ext = lowercase(path)
	df = endswith(ext, ".csv") ? CSV.read(path, DataFrame) : DataFrame(Parquet2.Dataset(path))
	return _simple_format_df(df)
end

function _read_simple_keyed(path::AbstractString; variable=nothing)
	df = _read_simple_df(path)
	if variable !== nothing
		df = df[_tab_str.(df.variable) .== string(variable), :]
	end
	empty_message = variable === nothing ?
		"No data rows found in $path" :
		"No data rows found for variable \"$variable\" in $path"
	isempty(df) && error(empty_message)
	return Dict(_parse_index_tuple(_tab_str(row.indices)) => Float64(row.value) for row in eachrow(df))
end

"""
    read_indices(path::AbstractString)

Read index components from a simple `(variable, indices, value)` CSV or Parquet file.

Parses the `indices` column of every row. Integer components become `Int`; other
components become `Symbol`.

# Returns
- `Vector{Union{Symbol, Int}}` when all rows have a single index
- `Matrix{Union{Symbol, Int}}` (`n×d`) when rows have `d` comma-separated indices

# Examples
```julia
read_indices("dims.csv")  # [:a, :b, :c] or [:a 2024; :b 2024; ...]
```

See also: [`read_variable`](@ref), [`read_sparse_array`](@ref), [`load`](@ref)
"""
function read_indices(path::AbstractString)
	df = _read_simple_df(path)
	isempty(df) && return IndexValue[]
	parsed = [_parse_index_tuple(_tab_str(row.indices)) for row in eachrow(df)]
	ndims = length(first(parsed))
	for p in parsed
		length(p) == ndims || error("Inconsistent number of indices across rows in $path")
	end
	if ndims == 1
		return IndexValue[only(p) for p in parsed]
	end
	mat = Matrix{IndexValue}(undef, length(parsed), ndims)
	for (i, p) in enumerate(parsed)
		mat[i, :] = collect(p)
	end
	return mat
end

"""
    read_sparse_array(path::AbstractString; variable=nothing)
    read_sparse_array(path::AbstractString, variable)

Read a simple `(variable, indices, value)` CSV or Parquet file.

When `variable` is given, only rows with that base name are read. Indices are parsed
as in [`read_indices`](@ref).

# Returns
A [`KeyedData`](@ref) keyed by the parsed index tuples. A coordinate that the file
does not store reads as `nothing`.

# Examples
```julia
read_sparse_array("data.csv")           # all variables
read_sparse_array("data.csv", "x")      # one variable
read_sparse_array("data.csv"; variable="x")
```

See also: [`read_variable`](@ref), [`read_indices`](@ref), [`load`](@ref)
"""
read_sparse_array(path::AbstractString; variable=nothing) = KeyedData(_read_simple_keyed(path; variable))
read_sparse_array(path::AbstractString, variable) = read_sparse_array(path; variable)

"""
    read_variable(path::AbstractString, var; default=nothing, variable=base_name(var))

Read values from a simple-format file aligned to a JuMP variable container.

Unlike [`load`](@ref), this does not build a full `ModelDictionary`; it returns a
plain array matching `var`'s shape and key order. Use `variable` to read from a
differently named column in the file.

# Arguments
- `path`: Path to a `.csv` or `.parquet` file in simple format
- `var`: JuMP variable or container whose keys define the output layout
- `default`: Value for indices missing from the file (default `nothing`)
- `variable`: Base name to look up in the file (default: `base_name(var)`)

# Examples
```julia
read_variable("data.csv", x)                  # match keys of x
read_variable("data.csv", y; default=0.0)     # fill gaps with 0
read_variable("data.csv", N_a; variable="nPop")  # rename on read
```

See also: [`load`](@ref), [`read_sparse_array`](@ref)
"""
function read_variable(path::AbstractString, var; default=nothing, variable=base_name(var))
	data = _read_simple_keyed(path; variable)
	return [get(data, _index_tuple(key), default) for key in keys(var)]
end

"""Load from a DataFrame in simple (variable, indices, value) format."""
function _load_simple(df::DataFrame, model::AbstractModel, rename_dict::Dict{String, String}, slice_dict::Dict{String, Tuple{String, Vector{String}, Vector{Int}}})
	data_index = Dict{Tuple{String, String}, Float64}()
	for row in eachrow(df)
		key = (_tab_str(row.variable), _tab_str(row.indices))
		data_index[key] = row.value
	end

	d = ModelDictionary(model)
	# The model's canonical file keys do not depend on the source or rename
	# rules. Parse them once per layout revision, shared by every loaded dataset.
	# The layout clears this cache whenever variables are renamed or changed.
	model_keys = get!(d._layout.selection_cache, :SquareModels_load_keys) do
		prepared = Vector{Tuple{String, String}}(undef, length(d._layout.variables))
		for (slot, variable) in enumerate(d._layout.variables)
			base, indices = _var_to_key(variable)
			prepared[slot] = (String(base), String(indices))
		end
		prepared
	end::Vector{Tuple{String, String}}
	for (slot, (base, indices)) in enumerate(model_keys)

		# Check for slice mapping first
		if haskey(slice_dict, base)
			src_symbol, fixed_indices, wildcard_positions = slice_dict[base]
			lookup_key = _build_slice_key(indices, fixed_indices, wildcard_positions)
			key = (src_symbol, lookup_key)
		else
			# Use renamed base if specified, otherwise use original
			lookup_base = get(rename_dict, base, base)
			key = (lookup_base, indices)
		end

		d.dictionary.values[slot] = get(data_index, key, nothing)
	end
	return d
end

"""Load from a Parquet file."""
function _load_parquet(path::AbstractString, model::AbstractModel, rename_dict::Dict{String, String}, slice_dict::Dict{String, Tuple{String, Vector{String}, Vector{Int}}})
	df = DataFrame(Parquet2.Dataset(path))
	data_df = if "variable" in names(df) && "indices" in names(df)
		_simple_format_df(df)
	elseif "name" in names(df) && "id" in names(df)
		_convert_gekko_format(df)
	else
		error("Unknown parquet format. Expected columns: (variable, indices, value) or Gekko format (id, name, dim1, dim2, period, value)")
	end
	return _load_simple(data_df, model, rename_dict, slice_dict)
end

"""Load from a CSV file."""
function _load_csv(path::AbstractString, model::AbstractModel, rename_dict::Dict{String, String}, slice_dict::Dict{String, Tuple{String, Vector{String}, Vector{Int}}})
	return _load_simple(_simple_format_df(CSV.read(path, DataFrame)), model, rename_dict, slice_dict)
end


"""
Build rename and slice dictionaries from Pair arguments and keyword arguments.

Values containing brackets (e.g., "vC[:cTot,:]") are parsed as slice specifications.
Simple strings are treated as renames.
"""
function _build_rename_and_slice_dicts(renames::Tuple, kwargs)
	rename_dict = Dict{String, String}()
	slice_dict = Dict{String, Tuple{String, Vector{String}, Vector{Int}}}()

	function process_mapping(model_var::String, spec::String)
		if contains(spec, "[")
			# Slice specification
			gdx_symbol, fixed_indices, wildcard_positions = _parse_slice_spec(spec)
			slice_dict[model_var] = (gdx_symbol, fixed_indices, wildcard_positions)
		else
			# Simple rename
			rename_dict[model_var] = spec
		end
	end

	for (k, v) in renames
		process_mapping(_to_base_name(k), string(v))
	end
	for (k, v) in pairs(kwargs)
		process_mapping(string(k), string(v))
	end

	return rename_dict, slice_dict
end

"""Extract base variable name from various input types. Always returns String."""
_to_base_name(x::Symbol) = string(x)
_to_base_name(x::AbstractString) = String(x)
_to_base_name(x::AbstractVariableRef) = String(first(parse_variable_name(name(x))))
function _to_base_name(x::AbstractArray{<:AbstractVariableRef})
	# For JuMP variable containers, extract base name from first element
	String(first(parse_variable_name(name(first(x)))))
end

"""Convert Gekko parquet format to simple (variable, indices, value) format."""
function _convert_gekko_format(df::DataFrame)
	# Separate metadata rows (have name) from data rows (have value but no name)
	metadata = df[.!ismissing.(df.name), [:id, :name, :dim1, :dim2]]
	data = df[ismissing.(df.name) .& .!isnan.(coalesce.(df.value, NaN)), [:id, :period, :value]]

	# Join metadata to data
	joined = leftjoin(data, metadata, on=:id)

	# Build indices string from dim1, dim2, period
	function build_indices(row)
		parts = String[]
		!ismissing(row.dim1) && push!(parts, string(row.dim1))
		!ismissing(row.dim2) && push!(parts, string(row.dim2))
		!ismissing(row.period) && push!(parts, string(row.period))
		return join(parts, ",")
	end

	result = DataFrame(
		variable = coalesce.(joined.name, ""),
		indices = build_indices.(eachrow(joined)),
		value = Float64.(joined.value)
	)

	# Filter out rows with empty variable names
	return result[result.variable .!= "", :]
end

"""
Convert a JuMP variable to the (variable, indices) key format.
E.g., x → ("x", ""), y[1,2] → ("y", "1,2")
"""
function _var_to_key(var::AbstractVariableRef)
	base, indices = parse_variable_name(name(var))
	return (base, indices)
end

"""
Parse a slice specification string into (gdx_symbol, fixed_indices, wildcard_positions).

The string format is "symbol[idx1,idx2,...]" where:
- Fixed indices (like :cTot or cTot) become part of the lookup key
- Wildcards (:) indicate positions that should be filled from the target variable's indices

# Examples
```julia
_parse_slice_spec("vC[:cTot,:]")   # ("vC", ["cTot"], [2])
_parse_slice_spec("vK[:iTot,:tot,:]")  # ("vK", ["iTot", "tot"], [3])
_parse_slice_spec("nPop")  # ("nPop", [], [])  - simple rename
```
"""
function _parse_slice_spec(spec::AbstractString)
	# Handle simple rename case (no brackets)
	m = match(r"^([^\[]+)\[(.+)\]$", spec)
	isnothing(m) && return (spec, String[], Int[])

	gdx_symbol = m.captures[1]
	indices_str = m.captures[2]

	# Split by comma, respecting that indices might contain colons
	parts = split(indices_str, ",")

	fixed_indices = String[]
	wildcard_positions = Int[]

	for (i, part) in enumerate(parts)
		part = strip(part)
		if part == ":"
			push!(wildcard_positions, i)
		else
			# Strip leading colon if present (e.g., :cTot -> cTot)
			idx = startswith(part, ":") ? part[2:end] : part
			push!(fixed_indices, idx)
		end
	end

	return (gdx_symbol, fixed_indices, wildcard_positions)
end

"""
Build the GDX lookup key for a slice mapping.

Given a target variable's indices and a slice specification, constructs the
indices string that should be looked up in the GDX file.

# Arguments
- `target_indices`: Indices from the target variable (e.g., "2025" or "15,2025")
- `fixed_indices`: Fixed parts of the slice (e.g., ["cTot"])
- `wildcard_positions`: Positions where target indices should be inserted

# Example
For target C[2025] with slice "vC[:cTot,:]":
- target_indices = "2025"
- fixed_indices = ["cTot"]
- wildcard_positions = [2]
- Result: "cTot,2025"
"""
function _build_slice_key(target_indices::AbstractString, fixed_indices::Vector{String}, wildcard_positions::Vector{Int})
	isempty(wildcard_positions) && return join(fixed_indices, ",")

	target_parts = isempty(target_indices) ? String[] : split(target_indices, ",")

	# Total positions = fixed + wildcards
	total_positions = length(fixed_indices) + length(wildcard_positions)
	result = Vector{String}(undef, total_positions)

	fixed_idx = 1
	target_idx = 1

	for pos in 1:total_positions
		if pos in wildcard_positions
			result[pos] = target_idx <= length(target_parts) ? string(target_parts[target_idx]) : ""
			target_idx += 1
		else
			result[pos] = fixed_indices[fixed_idx]
			fixed_idx += 1
		end
	end

	return join(result, ",")
end

# ----------------------------------------------------------------------------------------------------------------------
# Dot access
# ----------------------------------------------------------------------------------------------------------------------
Base.setproperty!(d::ModelDictionary, name::Symbol, value) = setindex!(d, value, String(name))
Base.getproperty(d::ModelDictionary, sym::Symbol) = sym in fieldnames(typeof(d)) ? getfield(d, sym) : d[String(sym)]

# ----------------------------------------------------------------------------------------------------------------------
# Broadcasting
# ----------------------------------------------------------------------------------------------------------------------
struct ModelDictionaryStyle <: Broadcast.BroadcastStyle end
Base.BroadcastStyle(::Type{<:ModelDictionary}) = ModelDictionaryStyle()
Base.BroadcastStyle(::ModelDictionaryStyle, ::Broadcast.DefaultArrayStyle{0}) = ModelDictionaryStyle()
Base.BroadcastStyle(s::ModelDictionaryStyle, ::ModelDictionaryStyle) = s
# Model changes must be synchronized before broadcast axes are inferred.
Base.Broadcast.instantiate(bc::Broadcast.Broadcasted{ModelDictionaryStyle}) = bc

# ModelDictionary participates directly in broadcasting (not converted via collect)
Base.broadcastable(md::ModelDictionary) = md
Base.axes(md::ModelDictionary) = (Base.OneTo(length(md)),)
Base.getindex(md::ModelDictionary, i::Int) = (_ensure_data_layout!(md); md.dictionary.values[i])

# Find the first ModelDictionary in broadcast arguments (including nested Broadcasted)
_find_model_dict(md::ModelDictionary) = md
_find_model_dict(bc::Broadcast.Broadcasted) = _find_model_dict(bc.args)
_find_model_dict(::Any) = nothing
function _find_model_dict(args::Tuple)
	for arg in args
		result = _find_model_dict(arg)
		isnothing(result) || return result
	end
	nothing
end

_bc_values(md::ModelDictionary) = md.dictionary.values
_bc_values(x) = x

_validate_dictionary_broadcast(reference::ModelDictionary, arg) = nothing
function _validate_dictionary_broadcast(reference::ModelDictionary, md::ModelDictionary)
	_ensure_data_layout!(md)
	_assert_aligned(reference, md)
	return nothing
end
function _validate_dictionary_broadcast(reference::ModelDictionary, bc::Broadcast.Broadcasted)
	foreach(arg -> _validate_dictionary_broadcast(reference, arg), bc.args)
	return nothing
end

function _dictionary_values_broadcast(reference::ModelDictionary, bc::Broadcast.Broadcasted)
	_ensure_data_layout!(reference)
	_validate_dictionary_broadcast(reference, bc)
	flat = Broadcast.flatten(bc)
	# Borrow buffers; only the result of an allocating broadcast needs storage.
	return Broadcast.broadcasted(_lift(flat.f), map(_bc_values, flat.args)...)
end

# Lift a function to propagate nothing (like NaN propagation)
_lift(f) = (args...) -> any(isnothing, args) ? nothing : f(args...)

function Base.copy(bc::Broadcast.Broadcasted{ModelDictionaryStyle})
	md = _find_model_dict(bc.args)
	new_values = Base.materialize(_dictionary_values_broadcast(md, bc))
	return _derived_dictionary(md, new_values)
end

function Base.copyto!(destination::ModelDictionary, bc::Broadcast.Broadcasted)
	values_bc = _dictionary_values_broadcast(destination, bc)
	# Base handles aliased views. Identical full value buffers are safe in place:
	# unlike a Window, they cannot contain repeated destination positions.
	Base.materialize!(destination.dictionary.values, values_bc)
	return destination
end

Base.materialize!(destination::ModelDictionary, bc::Broadcast.Broadcasted) =
	copyto!(destination, bc)

# ==============================================================================
# Comparison utilities
# ==============================================================================
"""
	keys_match(a::ModelDictionary, b::ModelDictionary) -> Bool

Check if two ModelDictionaries have matching structure: same keys with `nothing`
values in the same positions.

# Example
```julia
if keys_match(baseline, scenario)
	diffs = abs.(baseline .- scenario)
	# safe to compare numerically
end
```
"""
function keys_match(a::ModelDictionary, b::ModelDictionary)
	keys(a) == keys(b) || return false
	for k in keys(a)
		xor(isnothing(a[k]), isnothing(b[k])) && return false
	end
	return true
end

"""
	assert_no_diff(a::ModelDictionary, b::ModelDictionary; atol=1e-6, rtol=0.0, msg="")

Assert that two ModelDictionaries have no significant differences.

A difference passes if either `|a - b| <= atol` or, for a reference value
larger than `atol`, `|a - b| / |b| <= rtol`.

This approach uses absolute tolerance for small values and relative tolerance
for large values, avoiding issues with division by near-zero references.

Errors immediately if keys don't match (different keys or nothing/value mismatch).

# Example
```julia
assert_no_diff(pre_solve, post_solve, atol=1e-6, msg="Zero shock test failed")
assert_no_diff(baseline, scenario, atol=1e-6, rtol=0.01, msg="Differences exceed 1%")
```
"""
function assert_no_diff(a::ModelDictionary, b::ModelDictionary; atol::Real=1e-6, rtol::Real=0.0, msg::String="")
	error_msg = isempty(msg) ? "" : "$msg\n"

	# Check structural match
	if keys(a) != keys(b)
		error("$(error_msg)Cannot compare: dictionaries have different keys")
	end
	mismatches = [k for k in keys(a) if xor(isnothing(a[k]), isnothing(b[k]))]
	if !isempty(mismatches)
		error("$(error_msg)Cannot compare: $(length(mismatches)) keys have nothing/value mismatch: $(first(mismatches, 10))$(length(mismatches) > 10 ? "..." : "")")
	end

	# Check differences using MAKRO-style logic:
	# Pass if: |diff| <= atol AND (|ref| <= atol OR |diff/ref| <= rtol)
	violations = Tuple{String, Float64, Float64, Any, Any}[]  # (key, abs_diff, rel_diff, v1, v2)
	for k in keys(a)
		v1, v2 = a[k], b[k]
		isnothing(v1) && continue
		d = abs(v1 - v2)
		abs_ref = abs(v2)
		# Absolute check
		d <= atol && continue
		# If reference is small, only absolute matters (already failed above)
		if abs_ref <= atol
			push!(violations, (k, d, Inf, v1, v2))
		else
			# Check relative tolerance
			rel_d = d / abs_ref
			if rel_d > rtol
				push!(violations, (k, d, rel_d, v1, v2))
			end
		end
	end
	if !isempty(violations)
		sort!(violations, by=x -> -x[2])
		throw(ToleranceError(violations, Float64(atol), Float64(rtol), msg))
	end
	return true
end

_residual_tolerance(::Nothing, r::AbstractVariableRef, default::Real) = Float64(default)
function _source_name(r::AbstractVariableRef)
	base, indices = split_name(r)
	source_base = base[1:end - length(RESIDUAL_SUFFIX)]
	return source_base * indices
end

"""Look up a per-residual override in `tolerances` (exact residual key first, then
source-variable key), falling back to `default` (used for both `atol` and `rtol`
overrides via `tolerances`/`rtolerances`)."""
function _residual_tolerance(tolerances::ModelDictionary, r::AbstractVariableRef, default::Real)
	tol = tolerances[r]
	isnothing(tol) || return Float64(tol)
	tol = tolerances[_source_name(r)]
	isnothing(tol) ? Float64(default) : Float64(tol)
end

"""
	assert_residuals_small(data::ModelDictionary; atol=1e-6, rtol=0.0, msg="", tolerances=nothing, rtolerances=nothing)

Assert that every residual variable in the model is negligible relative to a
combined absolute/relative threshold: `|residual| <= max(atol, rtol * |variable|)`,
where `variable` is the endogenous/source variable the residual corresponds to
(same combination rule as Julia's `isapprox(atol=, rtol=)`, and as
[`assert_no_diff`](@ref)). This avoids the usual pitfall of relative tolerances
blowing up when the reference value is near zero: `atol` alone governs there.

Residual variables are identified by `RESIDUAL_SUFFIX` (see [`residuals`](@ref)).
After a successful solve they should all be ~0; a large residual indicates an
equation that is not satisfied by the data/solution.

`tolerances`/`rtolerances` may be `ModelDictionary`s with per-residual overrides
for `atol`/`rtol` respectively. Entries set by exact residual keys override only
those residuals; otherwise the corresponding endogenous/source-variable key is
used. Entries set to `nothing` fall back to `atol`/`rtol`. Use `Inf` as the
tolerance for residuals that are intentionally unchecked.

Residuals with a `nothing` value are skipped, as are relative comparisons when
the corresponding source variable has a `nothing` value. Throws an error listing
the offending residuals (sorted by magnitude) if any exceed their tolerance;
returns `true` otherwise.

# Example
```julia
assert_residuals_small(baseline; atol=1e-6, msg="Large residuals after solve")

# Allow residuals up to 0.1% of the corresponding variable's size, with a 1e-6 floor
assert_residuals_small(baseline; atol=1e-6, rtol=1e-3)
```

See also: [`assert_no_diff`](@ref), [`residuals`](@ref)
"""
function assert_residuals_small(data::ModelDictionary; atol::Real=1e-6, rtol::Real=0.0, msg::String="", tolerances::Union{Nothing, ModelDictionary}=nothing, rtolerances::Union{Nothing, ModelDictionary}=nothing)
	violations = Tuple{String, Float64, Float64}[]
	for r in residuals(data.model)
		v = data[r]
		isnothing(v) && continue
		abs_v = abs(v)
		tol = _residual_tolerance(tolerances, r, atol)
		rtol_r = _residual_tolerance(rtolerances, r, rtol)
		if rtol_r > 0
			base = data[_source_name(r)]
			isnothing(base) || (tol = max(tol, rtol_r * abs(base)))
		end
		abs_v > tol && push!(violations, (name(r), abs_v, tol))
	end
	if !isempty(violations)
		sort!(violations, by=x -> -x[2])
		throw(ResidualError(violations, Float64(atol), Float64(rtol), msg))
	end
	return true
end
