from collections.abc import Mapping
from dataclasses import fields, replace
from types import ModuleType
from typing import Any, Final

import models.experts.linear.config as config
from model_runtime.packages.runtime_values import validate_runtime_default_value_types
from models.experts.linear import runtime_options as options
from models.experts.linear._control_defaults import (
    expert_control_defaults,
    main_control_defaults,
    router_stack_defaults,
)
from models.experts.linear._residual import (
    ResidualStackSource,
    resolve_residual_stack_options,
)

_TOP_LEVEL_KEYS = ("batch_size", "learning_rate", "input_dim", "output_dim")
_STACK_FIELDS = {
    "hidden_dim": "hidden_dim",
    "num_layers": "num_layers",
    "last_layer_bias_option": "last_layer_bias_option",
    "apply_output_postprocessing_flag": "apply_output_postprocessing_flag",
    "activation": "activation",
    "layer_norm_position": "layer_norm_position",
    "normalization": "normalization",
    "residual_connection_option": "residual_connection_option",
    "residual_block_size": "residual_block_size",
    "residual_rms_norm_epsilon": "residual_rms_norm_epsilon",
    "residual_model_flag": "residual_model_flag",
    "dropout_probability": "dropout_probability",
    "bias_flag": "bias_flag",
}

_RUNTIME_FIELDS = {field.name for field in fields(options.RuntimeOptions)}


def builder_kwargs_from_flat(
    flat_kwargs: dict[str, Any],
    config_module: ModuleType,
) -> dict[str, Any]:
    """Atomically translate flat CLI/search values into local option groups."""

    kwargs = dict(flat_kwargs)
    result = {key: kwargs.pop(key) for key in _TOP_LEVEL_KEYS if key in kwargs}
    stack = _stack_options(kwargs, config_module, kwargs.pop("stack_options", None))
    submodule = _submodule_stack_options(
        kwargs,
        config_module,
        kwargs.pop("submodule_stack_options", None),
    )
    main_control = main_control_defaults(config_module)
    expert_control = expert_control_defaults(config_module)
    residual_stack_options = resolve_residual_stack_options(
        ResidualStackSource(
            coefficient_activation=kwargs.pop(
                "residual_coefficient_activation",
                config_module.RESIDUAL_COEFFICIENT_ACTIVATION,
            ),
            independent_flag=kwargs.pop(
                "residual_stack_independent_flag",
                config_module.RESIDUAL_STACK_INDEPENDENT_FLAG,
            ),
            hidden_dim=kwargs.pop(
                "residual_stack_hidden_dim",
                config_module.RESIDUAL_STACK_HIDDEN_DIM,
            ),
            num_layers=kwargs.pop(
                "residual_stack_num_layers",
                config_module.RESIDUAL_STACK_NUM_LAYERS,
            ),
            activation=kwargs.pop(
                "residual_stack_activation",
                config_module.RESIDUAL_STACK_ACTIVATION,
            ),
            layer_norm_position=kwargs.pop(
                "residual_stack_layer_norm_position",
                config_module.RESIDUAL_STACK_LAYER_NORM_POSITION,
            ),
            normalization=kwargs.pop(
                "residual_stack_normalization",
                config_module.RESIDUAL_STACK_NORMALIZATION,
            ),
            residual_connection_option=kwargs.pop(
                "residual_stack_residual_connection_option",
                config_module.RESIDUAL_STACK_RESIDUAL_CONNECTION_OPTION,
            ),
            residual_block_size=kwargs.pop(
                "residual_stack_residual_block_size",
                config_module.RESIDUAL_STACK_RESIDUAL_BLOCK_SIZE,
            ),
            residual_rms_norm_epsilon=kwargs.pop(
                "residual_stack_residual_rms_norm_epsilon",
                config_module.RESIDUAL_STACK_RESIDUAL_RMS_NORM_EPSILON,
            ),
            residual_model_flag=kwargs.pop(
                "residual_stack_residual_model_flag",
                config_module.RESIDUAL_STACK_RESIDUAL_MODEL_FLAG,
            ),
            dropout_probability=kwargs.pop(
                "residual_stack_dropout_probability",
                config_module.RESIDUAL_STACK_DROPOUT_PROBABILITY,
            ),
            last_layer_bias_option=kwargs.pop(
                "residual_stack_last_layer_bias_option",
                config_module.RESIDUAL_STACK_LAST_LAYER_BIAS_OPTION,
            ),
            apply_output_postprocessing_flag=kwargs.pop(
                "residual_stack_apply_output_postprocessing_flag",
                config_module.RESIDUAL_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
            ),
            bias_flag=kwargs.pop(
                "residual_stack_bias_flag",
                config_module.RESIDUAL_STACK_BIAS_FLAG,
            ),
        ),
        submodule,
    )
    stack = replace(
        stack,
        residual_stack_options=residual_stack_options,
    )
    submodule = replace(
        submodule,
        residual_stack_options=residual_stack_options,
    )
    result.update(
        stack_options=stack,
        submodule_stack_options=submodule,
        mixture_options=_mixture_options(
            kwargs, config_module, kwargs.pop("mixture_options", None)
        ),
        expert_stack_options=_expert_stack_options(
            kwargs,
            submodule,
            kwargs.pop("expert_stack_options", None),
            config_module,
        ),
        sampler_options=_sampler_options(
            kwargs, config_module, kwargs.pop("sampler_options", None)
        ),
        router_options=_router_options(
            kwargs, config_module, kwargs.pop("router_options", None)
        ),
        router_stack_options=_router_stack_options(
            kwargs,
            router_stack_defaults(config_module),
            kwargs.pop("router_stack_options", None),
        ),
        layer_controller_options=_layer_controller_options(
            kwargs,
            kwargs.pop("layer_controller_options", None),
            main_control.layer,
            flat_prefix="",
        ),
        dynamic_memory_options=_memory_options(
            kwargs,
            kwargs.pop("dynamic_memory_options", None),
            main_control.memory,
            flat_prefix="",
        ),
        recurrent_controller_options=_recurrent_options(
            kwargs,
            kwargs.pop("recurrent_controller_options", None),
            main_control.recurrent,
            flat_prefix="",
        ),
        expert_layer_controller_options=_layer_controller_options(
            kwargs,
            kwargs.pop("expert_layer_controller_options", None),
            expert_control.layer,
            flat_prefix="expert_",
        ),
        expert_dynamic_memory_options=_memory_options(
            kwargs,
            kwargs.pop("expert_dynamic_memory_options", None),
            expert_control.memory,
            flat_prefix="expert_",
        ),
        expert_recurrent_controller_options=_recurrent_options(
            kwargs,
            kwargs.pop("expert_recurrent_controller_options", None),
            expert_control.recurrent,
            flat_prefix="expert_",
        ),
    )
    for stack_key in (
        "stack_options",
        "submodule_stack_options",
        "expert_stack_options",
        "router_stack_options",
    ):
        result[stack_key] = replace(
            result[stack_key],
            residual_stack_options=residual_stack_options,
        )
    result.update(kwargs)
    return result


def _stack_options(
    kwargs: dict[str, Any],
    config: ModuleType,
    provided: options.ExpertsStackOptions | None,
) -> options.ExpertsStackOptions:
    value = provided or options.ExpertsStackOptions(
        hidden_dim=config.HIDDEN_DIM,
        bias_flag=config.STACK_BIAS_FLAG,
        layer_norm_position=config.LAYER_NORM_POSITION,
        normalization=config.NORMALIZATION,
        num_layers=config.STACK_NUM_LAYERS,
        activation=config.STACK_ACTIVATION,
        residual_connection_option=config.STACK_RESIDUAL_CONNECTION_OPTION,
        residual_block_size=config.STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=config.STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=config.STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
    )
    updates = _pop_updates(
        kwargs,
        {
            "hidden_dim": "hidden_dim",
            "stack_bias_flag": "bias_flag",
            "layer_norm_position": "layer_norm_position",
            "normalization": "normalization",
            "stack_num_layers": "num_layers",
            "stack_activation": "activation",
            "stack_residual_connection_option": "residual_connection_option",
            "stack_residual_block_size": "residual_block_size",
            "stack_residual_rms_norm_epsilon": "residual_rms_norm_epsilon",
            "stack_residual_model_flag": "residual_model_flag",
            "stack_dropout_probability": "dropout_probability",
            "stack_last_layer_bias_option": "last_layer_bias_option",
            "stack_apply_output_postprocessing_flag": "apply_output_postprocessing_flag",
        },
    )
    return replace(value, **updates) if updates else value


def _submodule_stack_options(
    kwargs: dict[str, Any],
    config: ModuleType,
    provided: options.ExpertsSubmoduleStackOptions | None,
) -> options.ExpertsSubmoduleStackOptions:
    value = provided or options.ExpertsSubmoduleStackOptions(
        hidden_dim=config.SUBMODULE_STACK_HIDDEN_DIM,
        num_layers=config.SUBMODULE_STACK_NUM_LAYERS,
        last_layer_bias_option=config.SUBMODULE_STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=config.SUBMODULE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
        activation=config.SUBMODULE_STACK_ACTIVATION,
        layer_norm_position=config.SUBMODULE_STACK_LAYER_NORM_POSITION,
        normalization=config.SUBMODULE_STACK_NORMALIZATION,
        residual_connection_option=config.SUBMODULE_STACK_RESIDUAL_CONNECTION_OPTION,
        residual_block_size=config.SUBMODULE_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.SUBMODULE_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.SUBMODULE_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.SUBMODULE_STACK_DROPOUT_PROBABILITY,
        bias_flag=config.SUBMODULE_STACK_BIAS_FLAG,
    )
    updates = _pop_updates(
        kwargs,
        {f"submodule_stack_{key}": field for key, field in _STACK_FIELDS.items()},
    )
    return replace(value, **updates) if updates else value


def _expert_stack_options(
    kwargs: dict[str, Any],
    inherited: options.ExpertsSubmoduleStackOptions,
    provided: options.ExpertsSubmoduleStackOptions | None,
    config_module: ModuleType,
) -> options.ExpertsSubmoduleStackOptions:
    value = provided or replace(
        inherited,
        layer_norm_position=config_module.EXPERT_STACK_LAYER_NORM_POSITION,
        normalization=config_module.EXPERT_STACK_NORMALIZATION,
        apply_output_postprocessing_flag=(
            config_module.EXPERT_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
    )
    updates = _pop_updates(
        kwargs,
        {
            "expert_stack_hidden_dim": "hidden_dim",
            "expert_stack_num_layers": "num_layers",
            "expert_stack_last_layer_bias_option": "last_layer_bias_option",
            "expert_stack_apply_output_postprocessing_flag": (
                "apply_output_postprocessing_flag"
            ),
            "expert_stack_activation": "activation",
            "expert_stack_layer_norm_position": "layer_norm_position",
            "expert_stack_normalization": "normalization",
            "expert_stack_residual_connection_option": ("residual_connection_option"),
            "expert_stack_residual_block_size": "residual_block_size",
            "expert_stack_residual_rms_norm_epsilon": "residual_rms_norm_epsilon",
            "expert_stack_residual_model_flag": "residual_model_flag",
            "expert_stack_dropout_probability": "dropout_probability",
            "expert_stack_bias_flag": "bias_flag",
            "expert_bias_flag": "bias_flag",
        },
    )
    return replace(value, **updates) if updates else value


def _router_stack_options(
    kwargs: dict[str, Any],
    defaults: options.ExpertsSubmoduleStackOptions,
    provided: options.ExpertsSubmoduleStackOptions | None,
) -> options.ExpertsSubmoduleStackOptions:
    value = provided or defaults
    updates = _pop_updates(
        kwargs,
        {
            "router_stack_hidden_dim": "hidden_dim",
            "router_stack_num_layers": "num_layers",
            "router_stack_last_layer_bias_option": "last_layer_bias_option",
            "router_stack_apply_output_postprocessing_flag": (
                "apply_output_postprocessing_flag"
            ),
            "router_stack_activation": "activation",
            "router_stack_layer_norm_position": "layer_norm_position",
            "router_stack_normalization": "normalization",
            "router_stack_residual_connection_option": ("residual_connection_option"),
            "router_stack_residual_block_size": "residual_block_size",
            "router_stack_residual_rms_norm_epsilon": "residual_rms_norm_epsilon",
            "router_stack_residual_model_flag": "residual_model_flag",
            "router_stack_dropout_probability": "dropout_probability",
            "router_stack_bias_flag": "bias_flag",
            "router_bias_flag": "bias_flag",
        },
    )
    return replace(value, **updates) if updates else value


def _mixture_options(
    kwargs: dict[str, Any],
    config: ModuleType,
    provided: options.ExpertsMixtureOptions | None,
) -> options.ExpertsMixtureOptions:
    value = provided or options.ExpertsMixtureOptions(
        top_k=config.TOP_K,
        num_experts=config.NUM_EXPERTS,
        capacity_factor=config.CAPACITY_FACTOR,
        dropped_token_behavior=config.DROPPED_TOKEN_BEHAVIOR,
        compute_expert_mixture_flag=config.COMPUTE_EXPERT_MIXTURE_FLAG,
        weighted_parameters_flag=config.WEIGHTED_PARAMETERS_FLAG,
        weighting_position_option=config.WEIGHTING_POSITION_OPTION,
        routing_initialization_mode=config.ROUTING_INITIALIZATION_MODE,
    )
    fields = (
        "top_k",
        "num_experts",
        "capacity_factor",
        "dropped_token_behavior",
        "compute_expert_mixture_flag",
        "weighted_parameters_flag",
        "weighting_position_option",
        "routing_initialization_mode",
    )
    updates = _pop_updates(kwargs, {name: name for name in fields})
    return replace(value, **updates) if updates else value


def _sampler_options(
    kwargs: dict[str, Any],
    config: ModuleType,
    provided: options.ExpertsSamplerOptions | None,
) -> options.ExpertsSamplerOptions:
    value = provided or options.ExpertsSamplerOptions(
        threshold=config.SAMPLER_THRESHOLD,
        filter_above_threshold=config.SAMPLER_FILTER_ABOVE_THRESHOLD,
        num_topk_samples=config.SAMPLER_NUM_TOPK_SAMPLES,
        normalize_probabilities_flag=config.SAMPLER_NORMALIZE_PROBABILITIES_FLAG,
        noisy_topk_flag=config.SAMPLER_NOISY_TOPK_FLAG,
        coefficient_of_variation_loss_weight=(
            config.SAMPLER_COEFFICIENT_OF_VARIATION_LOSS_WEIGHT
        ),
        switch_loss_weight=config.SAMPLER_SWITCH_LOSS_WEIGHT,
        zero_centred_loss_weight=config.SAMPLER_ZERO_CENTRED_LOSS_WEIGHT,
        mutual_information_loss_weight=config.SAMPLER_MUTUAL_INFORMATION_LOSS_WEIGHT,
    )
    updates = _pop_updates(
        kwargs,
        {
            "sampler_threshold": "threshold",
            "sampler_filter_above_threshold": "filter_above_threshold",
            "sampler_num_topk_samples": "num_topk_samples",
            "sampler_normalize_probabilities_flag": "normalize_probabilities_flag",
            "sampler_noisy_topk_flag": "noisy_topk_flag",
            "sampler_coefficient_of_variation_loss_weight": (
                "coefficient_of_variation_loss_weight"
            ),
            "sampler_switch_loss_weight": "switch_loss_weight",
            "sampler_zero_centred_loss_weight": "zero_centred_loss_weight",
            "sampler_mutual_information_loss_weight": (
                "mutual_information_loss_weight"
            ),
        },
    )
    return replace(value, **updates) if updates else value


def _router_options(
    kwargs: dict[str, Any],
    config: ModuleType,
    provided: options.ExpertsRouterOptions | None,
) -> options.ExpertsRouterOptions:
    value = provided or options.ExpertsRouterOptions(
        noisy_topk_flag=config.ROUTER_NOISY_TOPK_FLAG
    )
    if "router_noisy_topk_flag" not in kwargs:
        return value
    return replace(value, noisy_topk_flag=kwargs.pop("router_noisy_topk_flag"))


def _stack_source_updates(
    kwargs: dict[str, Any],
    flat_prefix: str,
    source: options.ExpertsSubmoduleStackSource,
) -> options.ExpertsSubmoduleStackSource:
    updates = _pop_updates(
        kwargs,
        {
            f"{flat_prefix}_independent_flag": "independent_flag",
            f"{flat_prefix}_hidden_dim": "hidden_dim",
            f"{flat_prefix}_num_layers": "num_layers",
            f"{flat_prefix}_last_layer_bias_option": "last_layer_bias_option",
            f"{flat_prefix}_apply_output_postprocessing_flag": (
                "apply_output_postprocessing_flag"
            ),
            f"{flat_prefix}_activation": "activation",
            f"{flat_prefix}_layer_norm_position": "layer_norm_position",
            f"{flat_prefix}_normalization": "normalization",
            f"{flat_prefix}_residual_connection_option": ("residual_connection_option"),
            f"{flat_prefix}_residual_block_size": "residual_block_size",
            f"{flat_prefix}_residual_rms_norm_epsilon": "residual_rms_norm_epsilon",
            f"{flat_prefix}_residual_model_flag": "residual_model_flag",
            f"{flat_prefix}_dropout_probability": "dropout_probability",
            f"{flat_prefix}_bias_flag": "bias_flag",
        },
    )
    return replace(source, **updates) if updates else source


def _layer_controller_options(
    kwargs: dict[str, Any],
    provided: options.ExpertsLayerControllerOptions | None,
    defaults: options.ExpertsLayerControllerOptions,
    *,
    flat_prefix: str,
) -> options.ExpertsLayerControllerOptions:
    gate_flag_key = (
        f"{flat_prefix}stack_gate_flag" if flat_prefix else "stack_gate_flag"
    )
    halting_flag_key = (
        f"{flat_prefix}stack_halting_flag" if flat_prefix else "stack_halting_flag"
    )
    value = provided or defaults
    updates = _pop_updates(
        kwargs,
        {
            gate_flag_key: "stack_gate_flag",
            f"{flat_prefix}gate_option": "gate_option",
            f"{flat_prefix}gate_activation": "gate_activation",
            halting_flag_key: "stack_halting_flag",
            f"{flat_prefix}halting_option": "halting_option",
            f"{flat_prefix}halting_threshold": "halting_threshold",
            f"{flat_prefix}halting_dropout": "halting_dropout",
            f"{flat_prefix}halting_hidden_state_mode": "halting_hidden_state_mode",
            f"{flat_prefix}halting_output_dim": "halting_output_dim",
            **({"shared_gate_config": "shared_gate_config"} if not flat_prefix else {}),
        },
    )
    updates["gate_stack_source"] = _stack_source_updates(
        kwargs, f"{flat_prefix}gate_stack", value.gate_stack_source
    )
    updates["halting_stack_source"] = _stack_source_updates(
        kwargs, f"{flat_prefix}halting_stack", value.halting_stack_source
    )
    return replace(value, **updates)


def _memory_options(
    kwargs: dict[str, Any],
    provided: options.ExpertsDynamicMemoryOptions | None,
    defaults: options.ExpertsDynamicMemoryOptions,
    *,
    flat_prefix: str,
) -> options.ExpertsDynamicMemoryOptions:
    value = provided or defaults
    updates = _pop_updates(
        kwargs,
        {
            f"{flat_prefix}memory_flag": "memory_flag",
            f"{flat_prefix}memory_option": "memory_option",
            f"{flat_prefix}memory_position_option": "memory_position_option",
            f"{flat_prefix}memory_test_time_training_learning_rate": (
                "memory_test_time_training_learning_rate"
            ),
            f"{flat_prefix}memory_test_time_training_num_inner_steps": (
                "memory_test_time_training_num_inner_steps"
            ),
        },
    )
    updates["memory_stack_source"] = _stack_source_updates(
        kwargs, f"{flat_prefix}memory_stack", value.memory_stack_source
    )
    return replace(value, **updates)


def _recurrent_options(
    kwargs: dict[str, Any],
    provided: options.ExpertsRecurrentControllerOptions | None,
    defaults: options.ExpertsRecurrentControllerOptions,
    *,
    flat_prefix: str,
) -> options.ExpertsRecurrentControllerOptions:
    recurrent_flat = f"{flat_prefix}recurrent_"
    value = provided or defaults
    updates = _pop_updates(
        kwargs,
        {
            f"{recurrent_flat}flag": "recurrent_flag",
            f"{recurrent_flat}max_steps": "recurrent_max_steps",
            f"{recurrent_flat}initial_iterations": "recurrent_initial_iterations",
            f"{recurrent_flat}gradient_transition_count": "recurrent_gradient_transition_count",
            f"{recurrent_flat}no_gradient_transition_count": "recurrent_no_gradient_transition_count",
            f"{recurrent_flat}iteration_increment": "recurrent_iteration_increment",
            f"{recurrent_flat}forward_calls_before_iteration_increment": (
                "recurrent_forward_calls_before_iteration_increment"
            ),
            f"{recurrent_flat}smooth_iteration_growth_flag": (
                "recurrent_smooth_iteration_growth_flag"
            ),
            f"{recurrent_flat}layer_norm_position": "recurrent_layer_norm_position",
            f"{recurrent_flat}normalization": "recurrent_normalization",
            f"{recurrent_flat}stack_gate_flag": "recurrent_stack_gate_flag",
            f"{recurrent_flat}gate_option": "recurrent_gate_option",
            f"{recurrent_flat}gate_activation": "recurrent_gate_activation",
            f"{recurrent_flat}stack_halting_flag": "recurrent_stack_halting_flag",
            f"{recurrent_flat}halting_option": "recurrent_halting_option",
            f"{recurrent_flat}halting_threshold": "recurrent_halting_threshold",
            f"{recurrent_flat}halting_dropout": "recurrent_halting_dropout",
            f"{recurrent_flat}halting_hidden_state_mode": (
                "recurrent_halting_hidden_state_mode"
            ),
        },
    )
    updates["recurrent_gate_stack_source"] = _stack_source_updates(
        kwargs, f"{recurrent_flat}gate_stack", value.recurrent_gate_stack_source
    )
    updates["recurrent_halting_stack_source"] = _stack_source_updates(
        kwargs,
        f"{recurrent_flat}halting_stack",
        value.recurrent_halting_stack_source,
    )
    return replace(value, **updates)


def _pop_updates(
    kwargs: dict[str, Any],
    mapping: Mapping[str, str],
) -> dict[str, Any]:
    return {field: kwargs.pop(key) for key, field in mapping.items() if key in kwargs}


def runtime_from_flat(
    flat_kwargs: dict[str, Any] | None = None,
    config_module: ModuleType = config,
) -> options.RuntimeOptions:
    flat = dict(flat_kwargs or {})
    validate_runtime_default_value_types(
        flat,
        package="models.experts.linear",
        config_module=config_module,
    )
    hidden_dim = flat.get("hidden_dim", config_module.HIDDEN_DIM)
    translated = builder_kwargs_from_flat(flat, config_module)
    values = {
        "batch_size": translated.pop("batch_size", config_module.BATCH_SIZE),
        "learning_rate": translated.pop(
            "learning_rate",
            config_module.LEARNING_RATE,
        ),
        "input_dim": translated.pop("input_dim", config_module.INPUT_DIM),
        "hidden_dim": hidden_dim,
        "output_dim": translated.pop("output_dim", config_module.OUTPUT_DIM),
        **translated,
    }
    unknown = set(values) - _RUNTIME_FIELDS
    if unknown:
        name = sorted(unknown)[0]
        raise TypeError(
            "LinearConfigBuilder.__init__() got an unexpected keyword "
            f"argument {name!r}"
        )
    return options.RuntimeOptions(**values)


DEFAULT_RUNTIME: Final[options.RuntimeOptions] = runtime_from_flat()


__all__ = [
    "DEFAULT_RUNTIME",
    "builder_kwargs_from_flat",
    "runtime_from_flat",
]
