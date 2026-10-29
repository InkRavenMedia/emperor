import unittest
from dataclasses import replace

import pytest
import torch

from emperor.attention import (
    IndependentAttentionConfig,
    SelfAttentionConfig,
    SelfAttentionProjectionStrategy,
)
from emperor.augmentations.adaptive_parameters import (
    AdaptiveLinearLayerConfig,
    AdaptiveParameterAugmentationConfig,
    AdaptiveParameterGroupingScopeOptions,
    AdditiveDynamicBiasConfig,
    DualModelDynamicWeightConfig,
    SingleModelDynamicWeightConfig,
    WeightDecayScheduleOptions,
    WeightNormalizationOptions,
    WeightNormalizationPositionOptions,
)
from emperor.augmentations.adaptive_parameters import (
    AdaptiveParameterInputOrderOptions as Order,
)
from emperor.augmentations.adaptive_parameters._linear_adapter import (
    AdaptiveLinearLayer,
)
from emperor.layers import (
    ActivationOptions,
    LastLayerBiasOptions,
    LayerConfig,
    LayerNormPositionOptions,
    LayerStackConfig,
)
from support.adaptive_grouping import grouping_value
from support.attention import build_attention_config, make_projection_model_config


def grouped_projection_model_config(group_count: int = 2) -> LayerStackConfig:
    return LayerStackConfig(
        hidden_dim=4,
        num_layers=1,
        last_layer_bias_option=LastLayerBiasOptions.DEFAULT,
        apply_output_postprocessing_flag=False,
        layer_config=LayerConfig(
            activation=ActivationOptions.DISABLED,
            layer_norm_position=LayerNormPositionOptions.DISABLED,
            residual_config=None,
            dropout_probability=0.0,
            gate_config=None,
            halting_config=None,
            memory_config=None,
            layer_model_config=AdaptiveLinearLayerConfig(
                bias_flag=True,
                adaptive_augmentation_config=AdaptiveParameterAugmentationConfig(
                    grouping_config=grouping_value(
                        AdaptiveParameterGroupingScopeOptions.SEQUENCE,
                        group_count,
                        input_order="SEQUENCE_FIRST",
                    ),
                    bias_config=AdditiveDynamicBiasConfig(
                        decay_schedule=WeightDecayScheduleOptions.DISABLED,
                        decay_rate=0.0,
                        decay_warmup_batches=0,
                        model_config=make_projection_model_config(),
                    ),
                ),
            ),
        ),
    )


def grouped_weight_projection_model_config(group_count: int = 2) -> LayerStackConfig:
    return LayerStackConfig(
        hidden_dim=4,
        num_layers=1,
        last_layer_bias_option=LastLayerBiasOptions.DEFAULT,
        apply_output_postprocessing_flag=False,
        layer_config=LayerConfig(
            activation=ActivationOptions.DISABLED,
            layer_norm_position=LayerNormPositionOptions.DISABLED,
            residual_config=None,
            dropout_probability=0.0,
            gate_config=None,
            halting_config=None,
            memory_config=None,
            layer_model_config=AdaptiveLinearLayerConfig(
                bias_flag=False,
                adaptive_augmentation_config=AdaptiveParameterAugmentationConfig(
                    grouping_config=grouping_value(
                        AdaptiveParameterGroupingScopeOptions.SEQUENCE,
                        group_count,
                        input_order="SEQUENCE_FIRST",
                    ),
                    weight_config=DualModelDynamicWeightConfig(
                        generator_depth=1,
                        decay_schedule=WeightDecayScheduleOptions.DISABLED,
                        decay_rate=0.0,
                        decay_warmup_batches=0,
                        normalization_option=WeightNormalizationOptions.DISABLED,
                        normalization_position_option=(
                            WeightNormalizationPositionOptions.DISABLED
                        ),
                        model_config=make_projection_model_config(),
                    ),
                ),
            ),
        ),
    )


def grouped_single_weight_projection_model_config(
    group_count: int = 2,
) -> LayerStackConfig:
    config = grouped_weight_projection_model_config(group_count)
    adaptive_config = config.layer_config.layer_model_config
    adaptive_config.adaptive_augmentation_config.weight_config = (
        SingleModelDynamicWeightConfig(
            generator_depth=1,
            decay_schedule=WeightDecayScheduleOptions.DISABLED,
            decay_rate=0.0,
            decay_warmup_batches=0,
            normalization_option=WeightNormalizationOptions.DISABLED,
            normalization_position_option=(WeightNormalizationPositionOptions.DISABLED),
            model_config=make_projection_model_config(),
        )
    )
    return config


def adaptive_leaf(projection_model):
    return projection_model[0].model


class AttentionAdaptiveGroupingTests(unittest.TestCase):
    def test_grouped_self_attention_generates_batch_times_group_count_contexts(self):
        config = build_attention_config(
            config_class=SelfAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
            self_attention_projection_strategy=(
                SelfAttentionProjectionStrategy.SEPARATE
            ),
        )
        config.batch_first_flag = True
        config.projection_model_config = grouped_projection_model_config(group_count=2)
        model = config.build()
        generator_shapes = []
        hooks = []
        for projection_model in (
            model.projector.query_model,
            model.projector.key_model,
            model.projector.value_model,
            model.projector.output_model,
        ):
            generator = (
                adaptive_leaf(projection_model)
                .adaptive_behaviour.bias_model.model[0]
                .model
            )
            hooks.append(
                generator.register_forward_hook(
                    lambda _module, args, _output: generator_shapes.append(
                        tuple(args[0].shape)
                    )
                )
            )
        inputs = torch.randn(2, 4, 4, requires_grad=True)

        try:
            output, _weights, loss = model(inputs, inputs, inputs)
        finally:
            for hook in hooks:
                hook.remove()

        self.assertEqual(tuple(output.shape), (2, 4, 4))
        self.assertEqual(generator_shapes, [(4, 4)] * 4)
        objective = output.square().mean()
        if loss is not None:
            objective = objective + loss
        objective.backward()
        self.assertIsNotNone(inputs.grad)
        self.assertTrue(torch.isfinite(inputs.grad).all())

    def test_grouped_self_attention_supports_sequence_major_and_unbatched_inputs(self):
        cases = (
            (False, torch.randn(4, 2, 4, requires_grad=True), (4, 2, 4), 4),
            (False, torch.randn(4, 4, requires_grad=True), (4, 4), 2),
        )

        for batch_first, inputs, expected_shape, context_count in cases:
            with self.subTest(expected_shape=expected_shape):
                config = build_attention_config(
                    config_class=SelfAttentionConfig,
                    batch_size=2,
                    num_heads=2,
                    embedding_dim=4,
                    target_sequence_length=4,
                    source_sequence_length=4,
                    self_attention_projection_strategy=(
                        SelfAttentionProjectionStrategy.SEPARATE
                    ),
                )
                config.batch_first_flag = batch_first
                config.projection_model_config = grouped_projection_model_config()
                model = config.build()
                generated_context_shapes = []
                hooks = []
                for projection_model in (
                    model.projector.query_model,
                    model.projector.key_model,
                    model.projector.value_model,
                    model.projector.output_model,
                ):
                    bias_model = adaptive_leaf(
                        projection_model
                    ).adaptive_behaviour.bias_model
                    hooks.append(
                        bias_model.register_forward_hook(
                            lambda _module,
                            args,
                            _output,
                            generated_context_shapes=generated_context_shapes: (
                                generated_context_shapes.append(tuple(args[1].shape))
                            )
                        )
                    )

                try:
                    output, _weights, loss = model(inputs, inputs, inputs)
                finally:
                    for hook in hooks:
                        hook.remove()

                self.assertEqual(tuple(output.shape), expected_shape)
                self.assertEqual(
                    generated_context_shapes,
                    [(context_count, 4)] * 4,
                )
                objective = output.square().mean()
                if loss is not None:
                    objective = objective + loss
                objective.backward()
                self.assertTrue(torch.isfinite(inputs.grad).all())

    def test_post_projection_key_value_extensions_preserve_grouping_contract(self):
        config = build_attention_config(
            config_class=SelfAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
            add_key_value_bias_flag=True,
            zero_attention_flag=True,
            self_attention_projection_strategy=(
                SelfAttentionProjectionStrategy.SEPARATE
            ),
        )
        config.batch_first_flag = True
        config.projection_model_config = grouped_projection_model_config()
        model = config.build()
        generated_context_shapes = []
        hooks = []
        for projection_model in (
            model.projector.query_model,
            model.projector.key_model,
            model.projector.value_model,
            model.projector.output_model,
        ):
            bias_model = adaptive_leaf(projection_model).adaptive_behaviour.bias_model
            hooks.append(
                bias_model.register_forward_hook(
                    lambda _module, args, _output: generated_context_shapes.append(
                        tuple(args[1].shape)
                    )
                )
            )
        inputs = torch.randn(2, 4, 4, requires_grad=True)

        try:
            output, _weights, loss = model(inputs, inputs, inputs)
        finally:
            for hook in hooks:
                hook.remove()

        self.assertEqual(tuple(output.shape), (2, 4, 4))
        self.assertEqual(generated_context_shapes, [(4, 4)] * 4)
        objective = output.square().mean()
        if loss is not None:
            objective = objective + loss
        objective.backward()
        self.assertTrue(torch.isfinite(inputs.grad).all())

    def test_all_projection_strategies_keep_dynamic_weights_context_batched(self):
        strategy_shapes = (
            (
                SelfAttentionProjectionStrategy.FUSED,
                [(4, 4, 12), (4, 4, 4)],
            ),
            (
                SelfAttentionProjectionStrategy.FUSED_KEY_VALUE,
                [(4, 4, 4), (4, 4, 8), (4, 4, 4)],
            ),
            (
                SelfAttentionProjectionStrategy.SEPARATE,
                [(4, 4, 4)] * 4,
            ),
        )

        for strategy, expected_shapes in strategy_shapes:
            with self.subTest(strategy=strategy):
                config = build_attention_config(
                    config_class=SelfAttentionConfig,
                    batch_size=2,
                    num_heads=2,
                    embedding_dim=4,
                    target_sequence_length=4,
                    source_sequence_length=4,
                    self_attention_projection_strategy=strategy,
                )
                config.batch_first_flag = True
                config.projection_model_config = grouped_weight_projection_model_config(
                    group_count=2
                )
                model = config.build()
                generated_weight_shapes = []
                hooks = []
                for leaf in model.projector.modules():
                    if not isinstance(leaf, AdaptiveLinearLayer):
                        continue
                    hooks.append(
                        leaf.adaptive_behaviour.weight_model.register_forward_hook(
                            lambda _module,
                            _args,
                            output,
                            generated_weight_shapes=generated_weight_shapes: (
                                generated_weight_shapes.append(tuple(output.shape))
                            )
                        )
                    )
                inputs = torch.randn(2, 4, 4, requires_grad=True)

                try:
                    output, _weights, loss = model(inputs, inputs, inputs)
                finally:
                    for hook in hooks:
                        hook.remove()

                self.assertEqual(tuple(output.shape), (2, 4, 4))
                self.assertEqual(generated_weight_shapes, expected_shapes)
                objective = output.square().mean()
                if loss is not None:
                    objective = objective + loss
                objective.backward()
                self.assertTrue(torch.isfinite(inputs.grad).all())

    def test_single_model_weight_rejects_rectangular_fused_projections(self):
        for strategy in (
            SelfAttentionProjectionStrategy.FUSED,
            SelfAttentionProjectionStrategy.FUSED_KEY_VALUE,
        ):
            with self.subTest(strategy=strategy):
                config = build_attention_config(
                    config_class=SelfAttentionConfig,
                    batch_size=2,
                    num_heads=2,
                    embedding_dim=4,
                    target_sequence_length=4,
                    source_sequence_length=4,
                    self_attention_projection_strategy=strategy,
                )
                config.projection_model_config = (
                    grouped_single_weight_projection_model_config()
                )

                with self.assertRaisesRegex(
                    ValueError,
                    "requires input_dim == output_dim",
                ):
                    config.build()

    def test_restrictive_attention_paths_fail_before_grouped_generator(self):
        inputs = torch.randn(2, 4, 4)
        cases = []

        causal_config = build_attention_config(
            config_class=SelfAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
            causal_attention_mask_flag=True,
            self_attention_projection_strategy=(
                SelfAttentionProjectionStrategy.SEPARATE
            ),
        )
        causal_config.batch_first_flag = True
        causal_config.projection_model_config = grouped_projection_model_config()
        with self.assertRaisesRegex(ValueError, "causal"):
            causal_config.build()

        masked_config = build_attention_config(
            config_class=SelfAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
            self_attention_projection_strategy=(
                SelfAttentionProjectionStrategy.SEPARATE
            ),
        )
        masked_config.batch_first_flag = True
        masked_config.projection_model_config = grouped_projection_model_config()
        cases.append(
            (
                "explicit mask",
                masked_config.build(),
                inputs,
                inputs,
                torch.zeros(4, 4),
            )
        )

        cross_config = build_attention_config(
            config_class=IndependentAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
        )
        cross_config.batch_first_flag = True
        cross_config.projection_model_config = grouped_projection_model_config()
        cases.append(
            (
                "cross attention",
                cross_config.build(),
                inputs,
                torch.randn(2, 4, 4),
                None,
            )
        )

        for name, model, query, key_value, attention_mask in cases:
            calls = []
            generator = (
                adaptive_leaf(model.projector.query_model)
                .adaptive_behaviour.bias_model.model[0]
                .model
            )
            hook = generator.register_forward_hook(
                lambda *_args, calls=calls: calls.append(True)
            )
            try:
                with self.subTest(name=name):
                    with self.assertRaisesRegex(
                        ValueError,
                        "context sharing is restricted",
                    ):
                        model(
                            query,
                            key_value,
                            key_value,
                            attention_mask=attention_mask,
                        )
                    self.assertEqual(calls, [])
            finally:
                hook.remove()

    def test_static_and_fused_cross_inputs_reject_before_grouped_generators(self):
        inputs = torch.randn(2, 4, 4)
        cases = []

        static_config = build_attention_config(
            config_class=SelfAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
            self_attention_projection_strategy=(
                SelfAttentionProjectionStrategy.SEPARATE
            ),
        )
        static_config.batch_first_flag = True
        static_config.projection_model_config = grouped_projection_model_config()
        static_values = torch.randn(4, 4, 2)
        cases.append(
            (
                "static key/value",
                static_config.build(),
                inputs,
                inputs,
                {"static_k": static_values, "static_v": static_values.clone()},
            )
        )

        fused_cross_config = build_attention_config(
            config_class=SelfAttentionConfig,
            batch_size=2,
            num_heads=2,
            embedding_dim=4,
            target_sequence_length=4,
            source_sequence_length=4,
            self_attention_projection_strategy=(
                SelfAttentionProjectionStrategy.FUSED_KEY_VALUE
            ),
        )
        fused_cross_config.batch_first_flag = True
        fused_cross_config.projection_model_config = grouped_projection_model_config()
        cases.append(
            (
                "fused key/value cross input",
                fused_cross_config.build(),
                inputs,
                torch.randn_like(inputs),
                {},
            )
        )

        for name, model, query, key_value, keywords in cases:
            calls = []
            hooks = []
            for leaf in model.projector.modules():
                if not isinstance(leaf, AdaptiveLinearLayer):
                    continue
                generator = leaf.adaptive_behaviour.bias_model.model[0].model
                hooks.append(
                    generator.register_forward_hook(
                        lambda *_args, calls=calls: calls.append(True)
                    )
                )
            try:
                with self.subTest(name=name):
                    with self.assertRaisesRegex(
                        ValueError,
                        "context sharing is restricted",
                    ):
                        model(query, key_value, key_value, **keywords)
                    self.assertEqual(calls, [])
            finally:
                for hook in hooks:
                    hook.remove()


if __name__ == "__main__":
    unittest.main()


def grouping_attention(
    *, sequence_length=4, input_order=Order.SEQUENCE_FIRST, batch_first=True
):
    config = build_attention_config(
        config_class=SelfAttentionConfig,
        embedding_dim=4,
        num_heads=2,
        batch_size=4,
        target_sequence_length=4,
        source_sequence_length=4,
    )
    config.batch_first_flag = batch_first
    config.projection_model_config = grouped_projection_model_config()
    augmentation = config.projection_model_config.layer_config.layer_model_config.adaptive_augmentation_config
    augmentation.grouping_config = replace(
        augmentation.grouping_config,
        sequence_length=sequence_length,
        input_order=input_order,
    )
    return config


@pytest.mark.parametrize(
    "mask",
    [
        torch.tensor([[False, False, False, True], [False] * 4]),
        torch.tensor([[0.0, 0.0, 0.0, -torch.inf], [0.0] * 4]),
    ],
)
def test_attention_all_valid_policy_rejects_exclusion_before_any_generator(mask):
    model = grouping_attention().build()
    calls = []
    hooks = [
        leaf.adaptive_behaviour.bias_model.register_forward_pre_hook(
            lambda *_: calls.append(True)
        )
        for leaf in model.modules()
        if isinstance(leaf, AdaptiveLinearLayer)
    ]
    inputs = torch.randn(2, 4, 4)
    try:
        with pytest.raises(ValueError, match="all-valid"):
            model(inputs, inputs, inputs, k_padding_mask=mask)
        assert not calls
        output, _, _ = model(inputs, inputs, inputs)
        assert output.shape == inputs.shape and calls
    finally:
        for hook in hooks:
            hook.remove()


@pytest.mark.parametrize(
    "mask",
    [
        torch.zeros(2, 4, dtype=torch.bool),
        torch.full((2, 4), -0.25),
        torch.full((2, 4), -1e100, dtype=torch.float64),
    ],
)
def test_attention_all_valid_padding_biases_remain_eligible(mask):
    model = grouping_attention().build()
    inputs = torch.randn(2, 4, 4)
    output, _, _ = model(inputs, inputs, inputs, k_padding_mask=mask)
    assert output.shape == inputs.shape


@pytest.mark.parametrize(
    "shape,declared_length", [((2, 4, 4), 2), ((4, 4, 4), 8), ((4, 2, 4), 4)]
)
def test_attention_checks_actual_length_even_when_flat_rows_are_divisible(
    shape, declared_length
):
    model = grouping_attention(sequence_length=declared_length).build()
    calls = []
    hooks = [
        leaf.adaptive_behaviour.bias_model.register_forward_pre_hook(
            lambda *_: calls.append(True)
        )
        for leaf in model.modules()
        if isinstance(leaf, AdaptiveLinearLayer)
    ]
    inputs = torch.randn(shape)
    try:
        with pytest.raises(ValueError, match="sequence_length"):
            model(inputs, inputs, inputs)
        assert not calls
    finally:
        for hook in hooks:
            hook.remove()


def test_attention_rejects_wrong_declared_order_before_rng_even_when_dimensions_equal():
    config = grouping_attention(input_order=Order.BATCH_FIRST)
    config.batch_size = 4
    before = torch.get_rng_state().clone()
    with pytest.raises(ValueError, match="SEQUENCE_FIRST"):
        config.build()
    torch.testing.assert_close(torch.get_rng_state(), before)


@pytest.mark.parametrize(
    "mask,diagnostic",
    [
        (torch.zeros(2, 3, dtype=torch.bool), "shape"),
        (torch.zeros(2, 4, dtype=torch.int64), "bool"),
    ],
)
def test_attention_ordinary_mask_errors_precede_grouping(mask, diagnostic):
    model = grouping_attention().build()
    inputs = torch.randn(2, 4, 4)
    with pytest.raises((RuntimeError, TypeError), match=diagnostic):
        model(inputs, inputs, inputs, k_padding_mask=mask)
