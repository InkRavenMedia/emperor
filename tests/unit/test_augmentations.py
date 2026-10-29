import unittest

import torch
import torch.nn as nn

import emperor.augmentations as augmentations
import emperor.augmentations.adaptive_parameters as adaptive_parameters
from emperor.augmentations.adaptive_parameters import (
    AdaptiveParameterAugmentationConfig,
    AdditiveDynamicBiasConfig,
    AffineTransformDynamicBiasConfig,
    AntiDynamicDiagonalConfig,
    AxisMaskConfig,
    BankExpansionFactorOptions,
    CombinedDynamicDiagonalConfig,
    DiagonalAxisMaskConfig,
    DualModelDynamicWeightConfig,
    DynamicBiasConfig,
    DynamicDiagonalConfig,
    DynamicWeightConfig,
    GeneratorDynamicBiasConfig,
    HypernetworkDynamicWeightConfig,
    LayeredWeightedBankDynamicWeightConfig,
    LowRankDynamicWeightConfig,
    MaskDimensionOptions,
    MultiplicativeDynamicBiasConfig,
    OuterProductMaskConfig,
    PerAxisScoreMaskConfig,
    SigmoidGatedDynamicBiasConfig,
    SingleModelDynamicWeightConfig,
    SoftWeightedBankDynamicWeightConfig,
    StandardDynamicDiagonalConfig,
    TanhGatedDynamicBiasConfig,
    TopSliceAxisMaskConfig,
    WeightDecayScheduleOptions,
    WeightedBankDynamicBiasConfig,
    WeightInformedScoreAxisMaskConfig,
    WeightNormalizationOptions,
    WeightNormalizationPositionOptions,
)
from emperor.augmentations.adaptive_parameters._augmentation import (
    AdaptiveParameterAugmentation,
)
from emperor.augmentations.adaptive_parameters._biases.base import DynamicBiasAbstract
from emperor.augmentations.adaptive_parameters._diagonals.base import (
    DynamicDiagonalAbstract,
)
from emperor.augmentations.adaptive_parameters._masks.base import AxisMaskAbstract
from emperor.augmentations.adaptive_parameters._weights.base import (
    DynamicWeightAbstract,
)
from emperor.layers import (
    ActivationOptions,
    LastLayerBiasOptions,
    LayerConfig,
    LayerNormPositionOptions,
    LayerStackConfig,
    ResidualConfig,
)
from emperor.linears import LinearLayerConfig
from emperor.nn import Module

ADAPTIVE_PARAMETER_PUBLIC_EXPORTS = (
    "DepthMappingHandlerConfig",
    "DepthMappingLayerStack",
    "DecayPolicy",
    "WeightNormalizationPolicy",
    "MatrixWeightsMixtureConfig",
    "MatrixBiasMixtureConfig",
    "MatrixWeightsMixture",
    "MatrixBiasMixture",
    "DiagonallyModulatedLowRankDynamicWeightConfig",
    "LowRankFactorSourceOptions",
    "AttentionGroupingConfig",
    "GroupingConfig",
    "MeanGroupingConfig",
    "MeanStdGroupingConfig",
    "RMSGroupingConfig",
    "SumGroupingConfig",
    "SummaryNormalizationOptions",
    "AdaptiveParameterAugmentationConfig",
    "AdaptiveParameterInputOrderOptions",
    "AdaptiveLinearLayerConfig",
    "DynamicWeightConfig",
    "SingleModelDynamicWeightConfig",
    "DualModelDynamicWeightConfig",
    "LowRankDynamicWeightConfig",
    "HypernetworkDynamicWeightConfig",
    "LayeredWeightedBankDynamicWeightConfig",
    "SoftWeightedBankDynamicWeightConfig",
    "DynamicBiasConfig",
    "AffineTransformDynamicBiasConfig",
    "AdditiveDynamicBiasConfig",
    "MultiplicativeDynamicBiasConfig",
    "SigmoidGatedDynamicBiasConfig",
    "TanhGatedDynamicBiasConfig",
    "GeneratorDynamicBiasConfig",
    "WeightedBankDynamicBiasConfig",
    "DynamicDiagonalConfig",
    "StandardDynamicDiagonalConfig",
    "AntiDynamicDiagonalConfig",
    "CombinedDynamicDiagonalConfig",
    "AxisMaskConfig",
    "WeightInformedScoreAxisMaskConfig",
    "PerAxisScoreMaskConfig",
    "TopSliceAxisMaskConfig",
    "OuterProductMaskConfig",
    "DiagonalAxisMaskConfig",
    "BankExpansionFactorOptions",
    "MaskDimensionOptions",
    "WeightDecayScheduleOptions",
    "WeightNormalizationOptions",
    "WeightNormalizationPositionOptions",
    "AdaptiveParameterGroupingScopeOptions",
    "AdaptiveParameterMonitorCallback",
    "WeightBankUtilizationMonitorCallback",
)


class TestAdaptiveParameterAugmentation(unittest.TestCase):
    def preset(
        self,
        input_dim: int = 12,
        output_dim: int = 24,
        weight_config: DynamicWeightConfig | None = None,
        diagonal_config: DynamicDiagonalConfig | None = None,
        bias_config: DynamicBiasConfig | None = None,
        mask_config: AxisMaskConfig | None = None,
        model_config: LayerStackConfig | None = None,
    ) -> AdaptiveParameterAugmentationConfig:
        return AdaptiveParameterAugmentationConfig(
            input_dim=input_dim,
            output_dim=output_dim,
            grouping_config=None,
            weight_config=weight_config,
            diagonal_config=diagonal_config,
            bias_config=bias_config,
            mask_config=mask_config,
            model_config=model_config,
        )

    def _make_weight_config(
        self,
        config_cls: type[DynamicWeightConfig] = DualModelDynamicWeightConfig,
        input_dim: int = 12,
        output_dim: int = 24,
        normalization_option: WeightNormalizationOptions = (
            WeightNormalizationOptions.L2_SCALE
        ),
        normalization_position_option: WeightNormalizationPositionOptions = (
            WeightNormalizationPositionOptions.BEFORE_OUTER_PRODUCT
        ),
        generator_depth: int = 2,
        bank_expansion_factor: BankExpansionFactorOptions | None = None,
        decay_schedule: WeightDecayScheduleOptions = (
            WeightDecayScheduleOptions.DISABLED
        ),
        decay_rate: float = 0.0,
        decay_warmup_batches: int = 0,
        model_config: LayerStackConfig | None = None,
    ) -> DynamicWeightConfig:
        if model_config is None:
            model_config = self._make_layer_stack_config(
                input_dim=input_dim, output_dim=output_dim
            )
        common_kwargs = dict(
            input_dim=input_dim,
            output_dim=output_dim,
            generator_depth=generator_depth,
            decay_schedule=decay_schedule,
            decay_rate=decay_rate,
            decay_warmup_batches=decay_warmup_batches,
            model_config=model_config,
        )
        if config_cls in {
            SingleModelDynamicWeightConfig,
            DualModelDynamicWeightConfig,
        }:
            return config_cls(
                **common_kwargs,
                normalization_option=normalization_option,
                normalization_position_option=normalization_position_option,
            )
        if config_cls in {
            LowRankDynamicWeightConfig,
            HypernetworkDynamicWeightConfig,
        }:
            return config_cls(
                **common_kwargs,
                normalization_option=normalization_option,
            )
        if config_cls in {
            LayeredWeightedBankDynamicWeightConfig,
            SoftWeightedBankDynamicWeightConfig,
        }:
            return config_cls(
                **common_kwargs,
                bank_expansion_factor=bank_expansion_factor,
            )
        return config_cls(**common_kwargs)

    def _weight_cases(
        self,
    ) -> list[tuple[type[DynamicWeightConfig], int, BankExpansionFactorOptions | None]]:
        input_dim = 12
        output_dim = 24
        return [
            (SingleModelDynamicWeightConfig, input_dim, None),
            (DualModelDynamicWeightConfig, output_dim, None),
            (LowRankDynamicWeightConfig, output_dim, None),
            (HypernetworkDynamicWeightConfig, output_dim, None),
            (
                LayeredWeightedBankDynamicWeightConfig,
                output_dim,
                BankExpansionFactorOptions.FACTOR_OF_TWO,
            ),
            (
                SoftWeightedBankDynamicWeightConfig,
                output_dim,
                BankExpansionFactorOptions.FACTOR_OF_TWO,
            ),
        ]

    def _make_diagonal_config(
        self,
        config_cls: type[DynamicDiagonalConfig] = StandardDynamicDiagonalConfig,
        input_dim: int = 12,
        output_dim: int = 24,
    ) -> DynamicDiagonalConfig:
        return config_cls(
            input_dim=input_dim,
            output_dim=output_dim,
            model_config=self._make_layer_stack_config(
                input_dim=input_dim, output_dim=output_dim
            ),
        )

    def _diagonal_cases(
        self,
    ) -> list[type[DynamicDiagonalConfig]]:
        return [
            StandardDynamicDiagonalConfig,
            AntiDynamicDiagonalConfig,
            CombinedDynamicDiagonalConfig,
        ]

    def _make_bias_config(
        self,
        config_cls: type[DynamicBiasConfig] = GeneratorDynamicBiasConfig,
        input_dim: int = 12,
        output_dim: int = 24,
        bias_flag: bool = True,
        bank_expansion_factor: BankExpansionFactorOptions | None = None,
        decay_schedule: WeightDecayScheduleOptions = (
            WeightDecayScheduleOptions.DISABLED
        ),
        decay_rate: float = 0.0,
        decay_warmup_batches: int = 0,
    ) -> DynamicBiasConfig:
        common_kwargs = dict(
            input_dim=input_dim,
            output_dim=output_dim,
            decay_schedule=decay_schedule,
            decay_rate=decay_rate,
            decay_warmup_batches=decay_warmup_batches,
            model_config=self._make_layer_stack_config(
                input_dim=input_dim, output_dim=output_dim
            ),
        )
        if config_cls is WeightedBankDynamicBiasConfig:
            return config_cls(
                **common_kwargs,
                bank_expansion_factor=bank_expansion_factor,
            )
        return config_cls(**common_kwargs)

    def _bias_cases(
        self,
    ) -> list[tuple[type[DynamicBiasConfig], BankExpansionFactorOptions | None]]:
        return [
            (AffineTransformDynamicBiasConfig, None),
            (AdditiveDynamicBiasConfig, None),
            (MultiplicativeDynamicBiasConfig, None),
            (SigmoidGatedDynamicBiasConfig, None),
            (TanhGatedDynamicBiasConfig, None),
            (GeneratorDynamicBiasConfig, None),
            (WeightedBankDynamicBiasConfig, BankExpansionFactorOptions.FACTOR_OF_FOUR),
        ]

    def _make_mask_config(
        self,
        input_dim: int = 12,
        output_dim: int = 24,
        config_cls: type[AxisMaskConfig] = WeightInformedScoreAxisMaskConfig,
        mask_dimension_option: MaskDimensionOptions = MaskDimensionOptions.COLUMN,
        mask_threshold: float = 0.5,
        mask_surrogate_scale: float = 10.0,
        mask_floor: float = 0.0,
        mask_transition_width: float | None = None,
    ) -> AxisMaskConfig:
        common_kwargs = dict(
            mask_threshold=mask_threshold,
            mask_surrogate_scale=mask_surrogate_scale,
            mask_floor=mask_floor,
            model_config=self._make_layer_stack_config(
                input_dim=input_dim, output_dim=output_dim
            ),
        )
        if config_cls in {
            WeightInformedScoreAxisMaskConfig,
            PerAxisScoreMaskConfig,
        }:
            return config_cls(
                **common_kwargs,
                mask_dimension_option=mask_dimension_option,
            )
        if config_cls is TopSliceAxisMaskConfig:
            return config_cls(
                **common_kwargs,
                mask_dimension_option=mask_dimension_option,
                mask_transition_width=mask_transition_width,
            )
        if config_cls is DiagonalAxisMaskConfig:
            return config_cls(
                **common_kwargs,
                mask_transition_width=mask_transition_width,
            )
        return config_cls(**common_kwargs)

    def _mask_cases(self) -> list[type[AxisMaskConfig]]:
        return [
            WeightInformedScoreAxisMaskConfig,
            PerAxisScoreMaskConfig,
            TopSliceAxisMaskConfig,
            OuterProductMaskConfig,
            DiagonalAxisMaskConfig,
        ]

    def _make_layer_stack_config(
        self,
        input_dim: int = 12,
        hidden_dim: int = 36,
        output_dim: int = 24,
        bias_flag: bool = True,
        num_layers: int = 2,
        activation: ActivationOptions = ActivationOptions.RELU,
        residual_connection_option: type[ResidualConfig] | None = None,
        dropout_probability: float = 0.0,
        last_layer_bias_option: LastLayerBiasOptions = LastLayerBiasOptions.DEFAULT,
        apply_output_postprocessing_flag: bool = True,
    ) -> LayerStackConfig:
        return LayerStackConfig(
            input_dim=input_dim,
            hidden_dim=hidden_dim,
            output_dim=output_dim,
            num_layers=num_layers,
            last_layer_bias_option=last_layer_bias_option,
            apply_output_postprocessing_flag=apply_output_postprocessing_flag,
            layer_config=LayerConfig(
                input_dim=input_dim,
                output_dim=output_dim,
                activation=activation,
                layer_norm_position=LayerNormPositionOptions.DISABLED,
                residual_config=None
                if residual_connection_option is None
                else residual_connection_option(),
                dropout_probability=dropout_probability,
                gate_config=None,
                halting_config=None,
                layer_model_config=LinearLayerConfig(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    bias_flag=bias_flag,
                ),
            ),
        )

    def _make_affine_callback(self):
        def callback(weights, bias, X):
            if weights.dim() == 3:
                output = torch.einsum("ij,ijk->ik", X, weights)
            else:
                output = torch.matmul(X, weights)
            if bias is not None:
                output = output + bias
            return output

        return callback

    def _make_weight_and_bias_params(
        self,
        input_dim: int = 12,
        output_dim: int = 24,
        batch_size: int | None = None,
        weight_requires_grad: bool = False,
        bias_initializer=nn.init.zeros_,
    ):
        if batch_size is None:
            weight_params = Module()._init_parameter_bank((input_dim, output_dim))
        else:
            weight_params = torch.randn(
                batch_size,
                input_dim,
                output_dim,
                requires_grad=weight_requires_grad,
            )
        bias_params = Module()._init_parameter_bank((output_dim,), bias_initializer)
        return weight_params, bias_params

    def test_public_exports_resolve(self):
        self.assertEqual(augmentations.__all__, ("adaptive_parameters",))
        self.assertIs(augmentations.adaptive_parameters, adaptive_parameters)
        self.assertFalse(hasattr(augmentations, "AdaptiveParameterAugmentation"))
        self.assertEqual(
            adaptive_parameters.__all__,
            ADAPTIVE_PARAMETER_PUBLIC_EXPORTS,
        )

        for name in ADAPTIVE_PARAMETER_PUBLIC_EXPORTS:
            with self.subTest(name=name):
                self.assertTrue(hasattr(adaptive_parameters, name), name)

    def test_root_configs_share_package_config_module(self):
        expected_module = "emperor.augmentations.adaptive_parameters._config"
        self.assertEqual(
            AdaptiveParameterAugmentationConfig.__module__,
            expected_module,
        )
        self.assertEqual(
            adaptive_parameters.AdaptiveLinearLayerConfig.__module__,
            expected_module,
        )

    def test_init_all_disabled(self):
        cfg = self.preset()
        model = AdaptiveParameterAugmentation(cfg)
        self.assertEqual(model.input_dim, 12)
        self.assertEqual(model.output_dim, 24)
        self.assertIsNone(model.weight_config)
        self.assertIsNone(model.diagonal_config)
        self.assertIsNone(model.bias_config)
        self.assertIsNone(model.mask_config)
        self.assertIsNone(model.model_config)

    def test_build_creates_adaptive_parameter_augmentation(self):
        cfg = self.preset(input_dim=2, output_dim=3)

        model = cfg.build()
        self.assertIsInstance(model, AdaptiveParameterAugmentation)
        self.assertEqual(model.input_dim, 2)
        self.assertEqual(model.output_dim, 3)

        overrides = AdaptiveParameterAugmentationConfig(input_dim=4, output_dim=5)
        overridden_model = cfg.build(overrides)
        self.assertIsInstance(overridden_model, AdaptiveParameterAugmentation)
        self.assertEqual(overridden_model.input_dim, 4)
        self.assertEqual(overridden_model.output_dim, 5)

    def test_init_with_weight_config(self):
        for config_cls, output_dim, bank_factor in self._weight_cases():
            with self.subTest(weight=config_cls.__name__):
                input_dim = 12
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    weight_config=self._make_weight_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                        bank_expansion_factor=bank_factor,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                self.assertIsNotNone(model.weight_model)
                self.assertIsInstance(model.weight_model, DynamicWeightAbstract)

    def test_init_with_diagonal_config(self):
        for config_cls in self._diagonal_cases():
            with self.subTest(f"diagonal={config_cls.__name__}"):
                cfg = self.preset(
                    diagonal_config=self._make_diagonal_config(config_cls=config_cls),
                )
                model = AdaptiveParameterAugmentation(cfg)
                self.assertIsNotNone(model.diagonal_model)
                self.assertIsInstance(model.diagonal_model, DynamicDiagonalAbstract)

    def test_init_with_bias_config(self):
        for config_cls, bank_factor in self._bias_cases():
            with self.subTest(f"bias={config_cls.__name__}"):
                cfg = self.preset(
                    bias_config=self._make_bias_config(
                        config_cls=config_cls,
                        bank_expansion_factor=bank_factor,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                self.assertIsNotNone(model.bias_model)
                self.assertIsInstance(model.bias_model, DynamicBiasAbstract)

    def test_init_with_mask_config(self):
        for config_cls in self._mask_cases():
            with self.subTest(f"mask={config_cls.__name__}"):
                cfg = self.preset(
                    mask_config=self._make_mask_config(config_cls=config_cls),
                )
                model = AdaptiveParameterAugmentation(cfg)
                self.assertIsNotNone(model.mask_model)
                self.assertIsInstance(model.mask_model, AxisMaskAbstract)

    def test_forward_with_each_weight_option(self):
        batch_size = 2
        input_dim = 12
        for config_cls, output_dim, bank_factor in self._weight_cases():
            with self.subTest(weight=config_cls.__name__):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    weight_config=self._make_weight_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                        bank_expansion_factor=bank_factor,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim, output_dim
                )
                input_tensor = torch.randn(batch_size, input_dim)
                callback = self._make_affine_callback()
                output = model(callback, weight_params, bias_params, input_tensor)
                self.assertEqual(output.shape, (batch_size, output_dim))

    def test_forward_with_each_diagonal_option(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        for config_cls in self._diagonal_cases():
            with self.subTest(f"diagonal={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    diagonal_config=self._make_diagonal_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim, output_dim
                )
                input_tensor = torch.randn(batch_size, input_dim)
                callback = self._make_affine_callback()
                output = model(callback, weight_params, bias_params, input_tensor)
                self.assertEqual(output.shape, (batch_size, output_dim))

    def test_forward_with_each_bias_option(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        for config_cls, bank_factor in self._bias_cases():
            with self.subTest(f"bias={config_cls.__name__}"):
                bias_config = self._make_bias_config(
                    config_cls=config_cls,
                    input_dim=input_dim,
                    output_dim=output_dim,
                    bank_expansion_factor=bank_factor,
                )
                bias_config.model_config = self._make_layer_stack_config(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    activation=ActivationOptions.LEAKY_RELU,
                )
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    bias_config=bias_config,
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim, output_dim
                )
                input_tensor = torch.randn(batch_size, input_dim)
                callback = self._make_affine_callback()
                output = model(callback, weight_params, bias_params, input_tensor)
                self.assertEqual(output.shape, (batch_size, output_dim))

    def test_forward_with_each_mask_option(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        for config_cls in self._mask_cases():
            with self.subTest(f"mask={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    mask_config=self._make_mask_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim, output_dim
                )
                input_tensor = torch.randn(batch_size, input_dim)
                callback = self._make_affine_callback()
                output = model(callback, weight_params, bias_params, input_tensor)
                self.assertEqual(output.shape, (batch_size, output_dim))

    def test_forward_all_disabled(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        cfg = self.preset(input_dim=input_dim, output_dim=output_dim)
        model = AdaptiveParameterAugmentation(cfg)

        weight_params, bias_params = self._make_weight_and_bias_params(
            input_dim, output_dim
        )
        input_tensor = torch.randn(batch_size, input_dim)
        callback = self._make_affine_callback()

        output = model(callback, weight_params, bias_params, input_tensor)
        expected = callback(weight_params, bias_params, input_tensor)
        self.assertEqual(output.shape, (batch_size, output_dim))
        self.assertTrue(
            torch.allclose(
                output.round(decimals=6),
                expected.round(decimals=6),
                atol=1e-6,
                rtol=1e-5,
            )
        )

    def test_forward_without_bias(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        cfg = self.preset(input_dim=input_dim, output_dim=output_dim)
        model = AdaptiveParameterAugmentation(cfg)

        weight_params = Module()._init_parameter_bank((input_dim, output_dim))
        input_tensor = torch.randn(batch_size, input_dim)
        callback = self._make_affine_callback()

        output = model(callback, weight_params, None, input_tensor)
        expected = callback(weight_params, None, input_tensor)
        self.assertEqual(output.shape, (batch_size, output_dim))
        self.assertTrue(
            torch.allclose(
                output.round(decimals=6),
                expected.round(decimals=6),
                atol=1e-6,
                rtol=1e-5,
            )
        )

    def test_diagonal_options_modify_weights(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        for config_cls in self._diagonal_cases():
            with self.subTest(f"diagonal={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    diagonal_config=self._make_diagonal_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)

                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim, output_dim
                )
                input_tensor = torch.randn(batch_size, input_dim)
                callback = self._make_affine_callback()

                output = model(callback, weight_params, bias_params, input_tensor)
                baseline = callback(weight_params, bias_params, input_tensor)
                self.assertFalse(torch.allclose(output, baseline, atol=1e-6))

    def test_bias_options_modify_output(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        for config_cls, bank_factor in self._bias_cases():
            with self.subTest(f"bias={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    bias_config=self._make_bias_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                        bank_expansion_factor=bank_factor,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)

                weight_params = Module()._init_parameter_bank((input_dim, output_dim))
                bias_params = torch.linspace(1.0, float(output_dim), output_dim)
                input_tensor = torch.randn(batch_size, input_dim)
                callback = self._make_affine_callback()

                output = model(callback, weight_params, bias_params, input_tensor)
                baseline = callback(weight_params, bias_params, input_tensor)
                self.assertFalse(torch.allclose(output, baseline, atol=1e-6))

    def test_init_raises_on_invalid_dimensions(self):
        invalid_configs = [
            ("missing_input_dim", {"output_dim": 24}),
            ("missing_output_dim", {"input_dim": 12}),
            ("zero_input_dim", {"input_dim": 0, "output_dim": 24}),
            ("negative_output_dim", {"input_dim": 12, "output_dim": -1}),
        ]

        for case, config_kwargs in invalid_configs:
            with self.subTest(case=case):
                cfg = AdaptiveParameterAugmentationConfig(
                    grouping_config=None,
                    **config_kwargs,
                )
                with self.assertRaises(ValueError):
                    AdaptiveParameterAugmentation(cfg)

    def test_init_raises_on_invalid_sub_config_type(self):
        cases = [
            ("weight_config", DynamicBiasConfig()),
            ("diagonal_config", self._make_weight_config()),
            ("bias_config", self._make_mask_config()),
            ("mask_config", self._make_diagonal_config()),
        ]

        for field_name, sub_config in cases:
            with self.subTest(field_name=field_name):
                cfg = self.preset(**{field_name: sub_config})
                with self.assertRaises(TypeError):
                    AdaptiveParameterAugmentation(cfg)

    def test_init_raises_on_invalid_model_config_type(self):
        cases = [
            {"model_config": LinearLayerConfig(bias_flag=True)},
            {
                "weight_config": self._make_weight_config(
                    config_cls=DualModelDynamicWeightConfig,
                    model_config=LinearLayerConfig(bias_flag=True),
                )
            },
        ]

        for kwargs in cases:
            with self.subTest(kwargs=kwargs):
                cfg = self.preset(**kwargs)
                with self.assertRaises(TypeError):
                    AdaptiveParameterAugmentation(cfg)

    def test_forward_validates_runtime_inputs(self):
        model = AdaptiveParameterAugmentation(self.preset(input_dim=12, output_dim=24))
        callback = self._make_affine_callback()
        weight_params, bias_params = self._make_weight_and_bias_params(12, 24)
        input_tensor = torch.randn(2, 12)

        cases = [
            ("callback", None, weight_params, bias_params, input_tensor, TypeError),
            ("weight_type", callback, [[1.0]], bias_params, input_tensor, TypeError),
            (
                "weight_rank",
                callback,
                torch.randn(2, 3, 12, 24),
                bias_params,
                input_tensor,
                ValueError,
            ),
            (
                "weight_shape",
                callback,
                torch.randn(12, 23),
                bias_params,
                input_tensor,
                ValueError,
            ),
            (
                "weight_batch",
                callback,
                torch.randn(3, 12, 24),
                bias_params,
                input_tensor,
                ValueError,
            ),
            ("bias_type", callback, weight_params, [0.0], input_tensor, TypeError),
            (
                "bias_shape",
                callback,
                weight_params,
                torch.randn(23),
                input_tensor,
                ValueError,
            ),
            (
                "bias_batch",
                callback,
                weight_params,
                torch.randn(3, 24),
                input_tensor,
                ValueError,
            ),
            ("input_type", callback, weight_params, bias_params, [[0.0]], TypeError),
            (
                "input_rank",
                callback,
                weight_params,
                bias_params,
                torch.randn(2, 3, 12),
                ValueError,
            ),
            (
                "input_shape",
                callback,
                weight_params,
                bias_params,
                torch.randn(2, 11),
                ValueError,
            ),
        ]

        for case, cb, weights, bias, inputs, error_type in cases:
            with self.subTest(case=case):
                with self.assertRaises(error_type):
                    model(cb, weights, bias, inputs)

    def test_init_raises_on_missing_model_config_for_all_enabled_sub_configs(self):
        def make_sub_config(name, option):
            if name == "weight":
                return option()
            if name == "diagonal":
                return option()
            if name == "bias":
                if option is WeightedBankDynamicBiasConfig:
                    return option(
                        bank_expansion_factor=BankExpansionFactorOptions.FACTOR_OF_TWO
                    )
                return option()
            return option()

        sub_config_options = [
            (
                "weight",
                [
                    SingleModelDynamicWeightConfig,
                    DualModelDynamicWeightConfig,
                    LowRankDynamicWeightConfig,
                    HypernetworkDynamicWeightConfig,
                    LayeredWeightedBankDynamicWeightConfig,
                    SoftWeightedBankDynamicWeightConfig,
                ],
            ),
            (
                "diagonal",
                [
                    StandardDynamicDiagonalConfig,
                    AntiDynamicDiagonalConfig,
                    CombinedDynamicDiagonalConfig,
                ],
            ),
            (
                "bias",
                [
                    AffineTransformDynamicBiasConfig,
                    AdditiveDynamicBiasConfig,
                    MultiplicativeDynamicBiasConfig,
                    SigmoidGatedDynamicBiasConfig,
                    TanhGatedDynamicBiasConfig,
                    GeneratorDynamicBiasConfig,
                    WeightedBankDynamicBiasConfig,
                ],
            ),
            ("mask", self._mask_cases()),
        ]

        for config_name, option_enum in sub_config_options:
            for option in option_enum:
                with self.subTest(config=config_name, option=option):
                    sub_config = make_sub_config(config_name, option)
                    cfg = AdaptiveParameterAugmentationConfig(
                        input_dim=12,
                        output_dim=24,
                        grouping_config=None,
                        **{f"{config_name}_config": sub_config},
                    )
                    with self.assertRaises(ValueError):
                        AdaptiveParameterAugmentation(cfg)

    def test_all_enabled_sub_configs_inherit_parent_model_config(self):
        input_dim = 12
        base_output_dim = 24
        sub_config_options = [
            (
                "weight",
                [
                    SingleModelDynamicWeightConfig,
                    DualModelDynamicWeightConfig,
                    LowRankDynamicWeightConfig,
                    HypernetworkDynamicWeightConfig,
                    LayeredWeightedBankDynamicWeightConfig,
                    SoftWeightedBankDynamicWeightConfig,
                ],
                self._make_weight_config,
                DynamicWeightAbstract,
                "weight_model",
            ),
            (
                "diagonal",
                [
                    StandardDynamicDiagonalConfig,
                    AntiDynamicDiagonalConfig,
                    CombinedDynamicDiagonalConfig,
                ],
                self._make_diagonal_config,
                DynamicDiagonalAbstract,
                "diagonal_model",
            ),
            (
                "bias",
                [
                    AffineTransformDynamicBiasConfig,
                    AdditiveDynamicBiasConfig,
                    MultiplicativeDynamicBiasConfig,
                    SigmoidGatedDynamicBiasConfig,
                    TanhGatedDynamicBiasConfig,
                    GeneratorDynamicBiasConfig,
                    WeightedBankDynamicBiasConfig,
                ],
                self._make_bias_config,
                DynamicBiasAbstract,
                "bias_model",
            ),
            (
                "mask",
                self._mask_cases(),
                self._make_mask_config,
                AxisMaskAbstract,
                "mask_model",
            ),
        ]

        for (
            config_name,
            option_enum,
            make_config,
            abstract_cls,
            model_attr,
        ) in sub_config_options:
            for option in option_enum:
                output_dim = (
                    input_dim
                    if config_name == "weight"
                    and option == SingleModelDynamicWeightConfig
                    else base_output_dim
                )
                bank_expansion_factor = None
                if config_name == "weight" and option in {
                    LayeredWeightedBankDynamicWeightConfig,
                    SoftWeightedBankDynamicWeightConfig,
                }:
                    bank_expansion_factor = BankExpansionFactorOptions.FACTOR_OF_TWO
                if config_name == "bias" and option == WeightedBankDynamicBiasConfig:
                    bank_expansion_factor = BankExpansionFactorOptions.FACTOR_OF_FOUR

                with self.subTest(config=config_name, option=option):
                    parent_model_config = self._make_layer_stack_config(
                        input_dim=input_dim,
                        output_dim=output_dim,
                    )
                    if config_name == "weight":
                        sub_config = make_config(
                            config_cls=option,
                            input_dim=input_dim,
                            output_dim=output_dim,
                            bank_expansion_factor=bank_expansion_factor,
                        )
                    elif config_name == "diagonal":
                        sub_config = make_config(
                            config_cls=option,
                            input_dim=input_dim,
                            output_dim=output_dim,
                        )
                    elif config_name == "bias":
                        sub_config_kwargs = {
                            "config_cls": option,
                            "input_dim": input_dim,
                            "output_dim": output_dim,
                        }
                        if bank_expansion_factor is not None:
                            sub_config_kwargs["bank_expansion_factor"] = (
                                bank_expansion_factor
                            )
                        sub_config = make_config(**sub_config_kwargs)
                    else:
                        sub_config_kwargs = {
                            "config_cls": option,
                            "input_dim": input_dim,
                            "output_dim": output_dim,
                        }
                        sub_config = make_config(**sub_config_kwargs)
                    sub_config.model_config = None
                    cfg = AdaptiveParameterAugmentationConfig(
                        input_dim=input_dim,
                        output_dim=output_dim,
                        grouping_config=None,
                        model_config=parent_model_config,
                        **{f"{config_name}_config": sub_config},
                    )

                    model = AdaptiveParameterAugmentation(cfg)

                    self.assertIsNone(sub_config.model_config)
                    self.assertIsNotNone(getattr(model, model_attr))
                    self.assertIsInstance(getattr(model, model_attr), abstract_cls)

    def test_gradients_flow_with_diagonal(self):
        batch_size = 2
        input_dim = 12
        output_dim = 24
        for config_cls in self._diagonal_cases():
            with self.subTest(f"diagonal={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    diagonal_config=self._make_diagonal_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim, output_dim
                )
                input_tensor = torch.randn(batch_size, input_dim, requires_grad=True)
                callback = self._make_affine_callback()
                output = model(callback, weight_params, bias_params, input_tensor)
                output.pow(2).sum().backward()
                grads = [p.grad for p in model.parameters() if p.requires_grad]
                non_none_grads = [
                    g for g in grads if g is not None and g.abs().sum() > 0
                ]
                self.assertTrue(len(non_none_grads) > 0)
                self.assertIsNotNone(input_tensor.grad)

    def test_gradients_flow_with_weight(self):
        batch_size = 2
        input_dim = 12
        for config_cls, output_dim, bank_factor in self._weight_cases():
            with self.subTest(weight=config_cls.__name__):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    weight_config=self._make_weight_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                        bank_expansion_factor=bank_factor,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim,
                    output_dim,
                    batch_size=batch_size,
                    weight_requires_grad=True,
                )
                input_tensor = torch.randn(batch_size, input_dim, requires_grad=True)

                def callback(weights, bias, X):
                    return weights

                output = model(callback, weight_params, bias_params, input_tensor)
                output.pow(2).sum().backward()
                grads = [p.grad for p in model.parameters() if p.requires_grad]
                non_none_grads = [
                    g for g in grads if g is not None and g.abs().sum() > 0
                ]
                self.assertTrue(len(non_none_grads) > 0)
                self.assertIsNotNone(input_tensor.grad)

    def test_gradients_flow_with_bias(self):
        batch_size = 2
        input_dim = 8
        output_dim = 4
        torch.manual_seed(0)
        for config_cls, bank_factor in self._bias_cases():
            with self.subTest(f"bias={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    bias_config=self._make_bias_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                        bank_expansion_factor=bank_factor,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params = Module()._init_parameter_bank((input_dim, output_dim))
                bias_params = torch.randn(output_dim)
                input_tensor = torch.randn(batch_size, input_dim, requires_grad=True)
                callback = self._make_affine_callback()
                output = model(callback, weight_params, bias_params, input_tensor)
                output.sum().backward()
                grads = [p.grad for p in model.parameters() if p.requires_grad]
                non_none_grads = [
                    g for g in grads if g is not None and g.abs().sum() > 0
                ]
                self.assertTrue(len(non_none_grads) > 0)
                self.assertIsNotNone(input_tensor.grad)

    def test_gradients_flow_with_mask(self):
        batch_size = 2
        input_dim = 4
        output_dim = 3
        torch.manual_seed(0)
        for config_cls in self._mask_cases():
            with self.subTest(f"mask={config_cls.__name__}"):
                cfg = self.preset(
                    input_dim=input_dim,
                    output_dim=output_dim,
                    mask_config=self._make_mask_config(
                        config_cls=config_cls,
                        input_dim=input_dim,
                        output_dim=output_dim,
                        mask_threshold=0.2,
                        mask_surrogate_scale=5.0,
                    ),
                )
                model = AdaptiveParameterAugmentation(cfg)
                weight_params, bias_params = self._make_weight_and_bias_params(
                    input_dim,
                    output_dim,
                    batch_size=batch_size,
                    weight_requires_grad=True,
                )
                input_tensor = torch.randn(batch_size, input_dim, requires_grad=True)

                def callback(weights, bias, X):
                    return weights

                output = model(callback, weight_params, bias_params, input_tensor)
                output.pow(2).sum().backward()
                grads = [p.grad for p in model.parameters() if p.requires_grad]
                non_none_grads = [
                    g for g in grads if g is not None and g.abs().sum() > 0
                ]
                self.assertTrue(len(non_none_grads) > 0)
                self.assertIsNotNone(input_tensor.grad)

    def test_forward_applies_adjustments_in_weight_diagonal_bias_mask_order(self):
        model = AdaptiveParameterAugmentation(self.preset(input_dim=2, output_dim=2))
        observed_steps = []
        base_weights = torch.tensor([[1.0, 2.0], [3.0, 4.0]])
        base_bias = torch.tensor([0.5, -1.0])
        input_tensor = torch.tensor([[1.0, 0.0], [0.0, 1.0]])

        class WeightStep(nn.Module):
            def forward(self, weights, X):
                observed_steps.append("weight")
                torch.testing.assert_close(weights, base_weights)
                torch.testing.assert_close(X, input_tensor)
                return weights + 1.0

        class DiagonalStep(nn.Module):
            def forward(self, weights, X):
                observed_steps.append("diagonal")
                torch.testing.assert_close(weights, base_weights + 1.0)
                torch.testing.assert_close(X, input_tensor)
                return weights * 2.0

        class BiasStep(nn.Module):
            def forward(self, bias, X):
                observed_steps.append("bias")
                torch.testing.assert_close(bias, base_bias)
                torch.testing.assert_close(X, input_tensor)
                return bias + 4.0

        class MaskStep(nn.Module):
            def forward(self, weights, X):
                observed_steps.append("mask")
                torch.testing.assert_close(weights, (base_weights + 1.0) * 2.0)
                torch.testing.assert_close(X, input_tensor)
                return weights - 3.0

        def callback(weights, bias, X):
            observed_steps.append("callback")
            return X @ weights + bias

        model.weight_model = WeightStep()
        model.diagonal_model = DiagonalStep()
        model.bias_model = BiasStep()
        model.mask_model = MaskStep()

        output = model(callback, base_weights, base_bias, input_tensor)

        expected_weights = ((base_weights + 1.0) * 2.0) - 3.0
        expected_bias = base_bias + 4.0
        expected_output = input_tensor @ expected_weights + expected_bias
        self.assertEqual(
            observed_steps, ["weight", "diagonal", "bias", "mask", "callback"]
        )
        torch.testing.assert_close(output, expected_output)

    def test_forward_full_pipeline(self):
        batch_size = 2
        input_dim = 12
        for weight_config_cls, output_dim, weight_bank_factor in self._weight_cases():
            for diagonal_config_cls in self._diagonal_cases():
                for bias_config_cls, bias_bank_factor in self._bias_cases():
                    for mask_config_cls in self._mask_cases():
                        msg = (
                            f"weight={weight_config_cls.__name__}, "
                            f"diagonal={diagonal_config_cls.__name__}, "
                            f"bias={bias_config_cls.__name__}, "
                            f"mask={mask_config_cls.__name__}"
                        )
                        with self.subTest(msg):
                            cfg = self.preset(
                                input_dim=input_dim,
                                output_dim=output_dim,
                                weight_config=self._make_weight_config(
                                    config_cls=weight_config_cls,
                                    input_dim=input_dim,
                                    output_dim=output_dim,
                                    bank_expansion_factor=weight_bank_factor,
                                ),
                                diagonal_config=self._make_diagonal_config(
                                    config_cls=diagonal_config_cls,
                                    input_dim=input_dim,
                                    output_dim=output_dim,
                                ),
                                bias_config=self._make_bias_config(
                                    config_cls=bias_config_cls,
                                    input_dim=input_dim,
                                    output_dim=output_dim,
                                    bank_expansion_factor=bias_bank_factor,
                                ),
                                mask_config=self._make_mask_config(
                                    config_cls=mask_config_cls,
                                    input_dim=input_dim,
                                    output_dim=output_dim,
                                ),
                            )
                            model = AdaptiveParameterAugmentation(cfg)
                            weight_params, bias_params = (
                                self._make_weight_and_bias_params(input_dim, output_dim)
                            )
                            input_tensor = torch.randn(batch_size, input_dim)
                            callback = self._make_affine_callback()
                            output = model(
                                callback, weight_params, bias_params, input_tensor
                            )
                            self.assertEqual(output.shape, (batch_size, output_dim))
                            self.assertIsInstance(output, torch.Tensor)
