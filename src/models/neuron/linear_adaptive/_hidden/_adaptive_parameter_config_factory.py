from __future__ import annotations

from emperor.augmentations.adaptive_parameters import (
    AdaptiveParameterAugmentationConfig,
    AxisMaskConfig,
    DiagonalAxisMaskConfig,
    DiagonallyModulatedLowRankDynamicWeightConfig,
    DualModelDynamicWeightConfig,
    DynamicBiasConfig,
    DynamicDiagonalConfig,
    DynamicWeightConfig,
    HypernetworkDynamicWeightConfig,
    LayeredWeightedBankDynamicWeightConfig,
    LowRankDynamicWeightConfig,
    MatrixBiasMixtureConfig,
    MatrixWeightsMixtureConfig,
    PerAxisScoreMaskConfig,
    SingleModelDynamicWeightConfig,
    SoftWeightedBankDynamicWeightConfig,
    TopSliceAxisMaskConfig,
    WeightedBankDynamicBiasConfig,
    WeightInformedScoreAxisMaskConfig,
)
from emperor.layers import LayerConfig, LayerStackConfig
from emperor.linears import LinearLayerConfig
from emperor.sampler import RouterConfig, SamplerConfig
from models.neuron.linear_adaptive._hidden.runtime_options import (
    AdaptiveGenerationOptions,
    AdaptiveProjectionOptions,
    GeneratorStackOptions,
    RuntimeOptions,
    StackOptions,
)
from models.neuron.linear_adaptive._residual import (
    ResidualStackOptions,
    build_residual_config,
)

_WEIGHT_OPTION_FIELDS: dict[type[DynamicWeightConfig], tuple[str, ...]] = {
    DiagonallyModulatedLowRankDynamicWeightConfig: (
        "normalization_option",
        "input_factor_source",
        "output_factor_source",
        "input_factor_model_config",
        "output_factor_model_config",
        "coefficient_model_config",
    ),
    SingleModelDynamicWeightConfig: (
        "normalization_option",
        "normalization_position_option",
    ),
    DualModelDynamicWeightConfig: (
        "normalization_option",
        "normalization_position_option",
    ),
    LowRankDynamicWeightConfig: ("normalization_option",),
    HypernetworkDynamicWeightConfig: ("normalization_option",),
    LayeredWeightedBankDynamicWeightConfig: ("bank_expansion_factor",),
    SoftWeightedBankDynamicWeightConfig: ("bank_expansion_factor",),
}
_BIAS_OPTION_FIELDS: dict[type[DynamicBiasConfig], tuple[str, ...]] = {
    WeightedBankDynamicBiasConfig: ("bank_expansion_factor",),
}
_MASK_OPTION_FIELDS: dict[type[AxisMaskConfig], tuple[str, ...]] = {
    WeightInformedScoreAxisMaskConfig: ("mask_dimension_option",),
    PerAxisScoreMaskConfig: ("mask_dimension_option",),
    TopSliceAxisMaskConfig: (
        "mask_dimension_option",
        "mask_transition_width",
    ),
    DiagonalAxisMaskConfig: ("mask_transition_width",),
}


def _selected_kwargs(
    table: dict[type, tuple[str, ...]],
    option: type,
    available: dict[str, object],
) -> dict[str, object]:
    return {name: available[name] for name in table.get(option, ())}


def _stack_config(
    options: StackOptions,
    residual_stack: ResidualStackOptions,
) -> LayerStackConfig:
    return LayerStackConfig(
        hidden_dim=options.hidden_dim,
        num_layers=options.num_layers,
        last_layer_bias_option=options.last_layer_bias_option,
        apply_output_postprocessing_flag=options.apply_output_postprocessing_flag,
        layer_config=LayerConfig(
            activation=options.activation,
            layer_norm_position=options.layer_norm_position,
            normalization=options.normalization,
            residual_config=build_residual_config(
                options.residual_connection_option,
                options.residual_model_flag,
                residual_stack,
                residual_block_size=options.residual_block_size,
                residual_rms_norm_epsilon=options.residual_rms_norm_epsilon,
            ),
            dropout_probability=options.dropout_probability,
            gate_config=None,
            halting_config=None,
            layer_model_config=LinearLayerConfig(bias_flag=options.bias_flag),
        ),
    )


def _independent_stack_config(
    options: GeneratorStackOptions | None,
    residual_stack: ResidualStackOptions,
) -> LayerStackConfig | None:
    return (
        _stack_config(options.stack, residual_stack)
        if options is not None and options.independent
        else None
    )


class AdaptiveParameterConfigFactory:
    def __init__(self, runtime: RuntimeOptions) -> None:
        self._runtime = runtime

    def build_hidden_config(self) -> AdaptiveParameterAugmentationConfig:
        runtime = self._runtime
        weight_config = None
        if runtime.weight.enabled:
            weight_config = self._weight_config(
                runtime.weight.option,
                generation_fields=self._generation_weight_fields(runtime.generation),
                generator_depth=runtime.weight.generator_depth,
                decay_schedule=runtime.weight.decay_schedule,
                decay_rate=runtime.weight.decay_rate,
                decay_warmup_batches=runtime.weight.decay_warmup_batches,
                normalization_option=runtime.weight.normalization_option,
                normalization_position_option=(
                    runtime.weight.normalization_position_option
                ),
                bank_expansion_factor=runtime.weight.bank_expansion_factor,
                model_config=_independent_stack_config(
                    runtime.weight.generator_stack,
                    runtime.residual_stack,
                ),
            )
        bias_config = None
        if runtime.bias.enabled:
            bias_config = self._bias_config(
                runtime.bias.option,
                generation_fields=self._generation_mixture_fields(
                    runtime.generation, "bias"
                ),
                decay_schedule=runtime.bias.decay_schedule,
                decay_rate=runtime.bias.decay_rate,
                decay_warmup_batches=runtime.bias.decay_warmup_batches,
                bank_expansion_factor=runtime.bias.bank_expansion_factor,
                model_config=_independent_stack_config(
                    runtime.bias.generator_stack,
                    runtime.residual_stack,
                ),
            )
        diagonal_config = None
        if runtime.diagonal.enabled:
            diagonal_config = self._diagonal_config(
                runtime.diagonal.option,
                model_config=_independent_stack_config(
                    runtime.diagonal.generator_stack,
                    runtime.residual_stack,
                ),
            )
        mask_config = None
        if runtime.mask.enabled:
            mask_config = self._mask_config(
                runtime.mask.row_mask_option,
                mask_dimension_option=runtime.mask.dimension_option,
                mask_threshold=runtime.mask.threshold,
                mask_surrogate_scale=runtime.mask.surrogate_scale,
                mask_floor=runtime.mask.floor,
                mask_transition_width=runtime.mask.transition_width,
                model_config=_independent_stack_config(
                    runtime.mask.generator_stack,
                    runtime.residual_stack,
                ),
            )
        return AdaptiveParameterAugmentationConfig(
            grouping_config=runtime.grouping_config,
            weight_config=weight_config,
            bias_config=bias_config,
            diagonal_config=diagonal_config,
            mask_config=mask_config,
            model_config=_stack_config(
                runtime.adaptive_generator_stack,
                runtime.residual_stack,
            ),
        )

    def build_projection_config(
        self,
        options: AdaptiveProjectionOptions,
    ) -> AdaptiveParameterAugmentationConfig:
        return AdaptiveParameterAugmentationConfig(
            grouping_config=options.grouping_config,
            weight_config=self._weight_config(
                options.weight_option,
                generation_fields=self._generation_weight_fields(options.generation),
                generator_depth=options.generator_depth,
                decay_schedule=options.weight_decay_schedule,
                decay_rate=options.weight_decay_rate,
                decay_warmup_batches=options.weight_decay_warmup_batches,
                normalization_option=options.weight_normalization_option,
                normalization_position_option=(
                    options.weight_normalization_position_option
                ),
                bank_expansion_factor=options.weight_bank_expansion_factor,
            ),
            bias_config=self._bias_config(
                options.bias_option,
                generation_fields=self._generation_mixture_fields(
                    options.generation, "bias"
                ),
                decay_schedule=options.bias_decay_schedule,
                decay_rate=options.bias_decay_rate,
                decay_warmup_batches=options.bias_decay_warmup_batches,
                bank_expansion_factor=options.bias_bank_expansion_factor,
            ),
            diagonal_config=self._diagonal_config(options.diagonal_option),
            mask_config=self._mask_config(
                options.row_mask_option,
                mask_dimension_option=options.mask_dimension_option,
                mask_threshold=options.mask_threshold,
                mask_surrogate_scale=options.mask_surrogate_scale,
                mask_floor=options.mask_floor,
                mask_transition_width=options.mask_transition_width,
            ),
            model_config=_stack_config(
                self._runtime.adaptive_generator_stack,
                self._runtime.residual_stack,
            ),
        )

    def _generation_weight_fields(self, options: AdaptiveGenerationOptions) -> dict:
        return {
            **self._generation_mixture_fields(options, "weight"),
            "input_factor_source": options.weight_input_factor_source,
            "output_factor_source": options.weight_output_factor_source,
            "input_factor_model_config": _independent_stack_config(
                options.weight_input_factor_generator_stack,
                self._runtime.residual_stack,
            ),
            "output_factor_model_config": _independent_stack_config(
                options.weight_output_factor_generator_stack,
                self._runtime.residual_stack,
            ),
            "coefficient_model_config": _independent_stack_config(
                options.weight_coefficient_generator_stack, self._runtime.residual_stack
            ),
        }

    def _generation_mixture_fields(
        self, options: AdaptiveGenerationOptions, family: str
    ) -> dict:
        return dict(
            num_experts=getattr(options, f"{family}_mixture_num_experts"),
            top_k=getattr(options, f"{family}_mixture_top_k"),
            sampler_config=SamplerConfig(
                num_experts=getattr(options, f"{family}_mixture_num_experts"),
                top_k=getattr(options, f"{family}_mixture_top_k"),
                threshold=0.0,
                filter_above_threshold=False,
                num_topk_samples=0,
                noisy_topk_flag=False,
                coefficient_of_variation_loss_weight=0.0,
                switch_loss_weight=0.0,
                zero_centred_loss_weight=0.0,
                mutual_information_loss_weight=0.0,
                normalize_probabilities_flag=(
                    getattr(options, f"{family}_mixture_normalize_probabilities_flag")
                    if getattr(
                        options, f"{family}_mixture_normalize_probabilities_flag"
                    )
                    is not None
                    else (getattr(options, f"{family}_mixture_top_k") or 0) > 1
                ),
                router_config=RouterConfig(
                    num_experts=getattr(options, f"{family}_mixture_num_experts"),
                    noisy_topk_flag=False,
                    model_config=_independent_stack_config(
                        getattr(options, f"{family}_mixture_router_generator_stack"),
                        self._runtime.residual_stack,
                    ),
                ),
            ),
        )

    @staticmethod
    def _weight_config(
        option,
        *,
        generator_depth,
        decay_schedule,
        decay_rate,
        decay_warmup_batches,
        normalization_option,
        normalization_position_option,
        bank_expansion_factor,
        model_config=None,
        generation_fields=None,
    ) -> DynamicWeightConfig | None:
        if option is None:
            return None
        if option is MatrixWeightsMixtureConfig:
            mixture_fields = {
                name: value
                for name, value in (generation_fields or {}).items()
                if name in ("num_experts", "top_k", "sampler_config")
            }
            return option(
                model_config=model_config,
                decay_schedule=decay_schedule,
                decay_rate=decay_rate,
                decay_warmup_batches=decay_warmup_batches,
                **mixture_fields,
            )
        kwargs = {
            "generator_depth": generator_depth,
            "decay_schedule": decay_schedule,
            "decay_rate": decay_rate,
            "decay_warmup_batches": decay_warmup_batches,
            "model_config": model_config,
        }
        kwargs.update(
            _selected_kwargs(
                _WEIGHT_OPTION_FIELDS,
                option,
                {
                    **(generation_fields or {}),
                    "normalization_option": normalization_option,
                    "normalization_position_option": normalization_position_option,
                    "bank_expansion_factor": bank_expansion_factor,
                },
            )
        )
        return option(**kwargs)

    @staticmethod
    def _bias_config(
        option,
        *,
        decay_schedule,
        decay_rate,
        decay_warmup_batches,
        bank_expansion_factor,
        model_config=None,
        generation_fields=None,
    ) -> DynamicBiasConfig | None:
        if option is None:
            return None
        if option is MatrixBiasMixtureConfig:
            mixture_fields = {
                name: value
                for name, value in (generation_fields or {}).items()
                if name in ("num_experts", "top_k", "sampler_config")
            }
            return option(
                model_config=model_config,
                decay_schedule=decay_schedule,
                decay_rate=decay_rate,
                decay_warmup_batches=decay_warmup_batches,
                **mixture_fields,
            )
        kwargs = {
            "decay_schedule": decay_schedule,
            "decay_rate": decay_rate,
            "decay_warmup_batches": decay_warmup_batches,
            "model_config": model_config,
        }
        kwargs.update(
            _selected_kwargs(
                _BIAS_OPTION_FIELDS,
                option,
                {"bank_expansion_factor": bank_expansion_factor},
            )
        )
        return option(**kwargs)

    @staticmethod
    def _diagonal_config(
        option,
        *,
        model_config=None,
    ) -> DynamicDiagonalConfig | None:
        return None if option is None else option(model_config=model_config)

    @staticmethod
    def _mask_config(
        option,
        *,
        mask_dimension_option,
        mask_threshold,
        mask_surrogate_scale,
        mask_floor,
        mask_transition_width,
        model_config=None,
    ) -> AxisMaskConfig | None:
        if option is None:
            return None
        kwargs = {
            "mask_threshold": mask_threshold,
            "mask_surrogate_scale": mask_surrogate_scale,
            "mask_floor": mask_floor,
            "model_config": model_config,
        }
        kwargs.update(
            _selected_kwargs(
                _MASK_OPTION_FIELDS,
                option,
                {
                    "mask_dimension_option": mask_dimension_option,
                    "mask_transition_width": mask_transition_width,
                },
            )
        )
        return option(**kwargs)
