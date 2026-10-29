import importlib
import inspect
import unittest
from dataclasses import replace
from pathlib import Path

import pytest
import torch
import torch.nn as nn

import models.gpt.expert_linear_adaptive.config as config
import models.gpt.expert_linear_adaptive.dataset_options as dataset_options
from emperor.attention import (
    MixtureOfAttentionHeadsConfig,
    SelfAttentionConfig,
)
from emperor.augmentations.adaptive_parameters import (
    AdaptiveLinearLayerConfig,
    CombinedDynamicDiagonalConfig,
    GeneratorDynamicBiasConfig,
    SingleModelDynamicWeightConfig,
    WeightDecayScheduleOptions,
    WeightNormalizationOptions,
    WeightNormalizationPositionOptions,
)
from emperor.datasets.text.language_modeling import WikiText103Hierarchical
from emperor.experiments.language_model import LanguageModelExperiment
from emperor.experts import MixtureOfExpertsConfig, MixtureOfExpertsModelConfig
from emperor.halting import StickBreakingConfig
from emperor.layers import (
    ActivationOptions,
    AttentionResidualConfig,
    LayerNormPositionOptions,
    RecurrentLayerConfig,
)
from emperor.transformer import (
    TransformerDecoderLayerConfig,
    TransformerDecoderLayerState,
)
from model_runtime.inspection import configuration_schema, serialize_overrides
from models.catalog import model_package
from models.cli_selection import resolve_cli_selection
from models.experiment_cli_parser import get_experiment_parser
from models.gpt.expert_linear_adaptive.config_builder import (
    GptExpertLinearAdaptiveConfigBuilder,
)
from models.gpt.expert_linear_adaptive.experiment_config import ExperimentConfig
from models.gpt.expert_linear_adaptive.model import Model
from models.gpt.expert_linear_adaptive.presets import (
    Experiment,
    ExperimentPreset,
    ExperimentPresets,
)
from models.gpt.expert_linear_adaptive.runtime_options import (
    GptEmbeddingOptions,
    GptLmHeadOptions,
    TransformerDecoderOptions,
)
from tests.model_packages.training_test_utils import (
    RandomLanguageModelDataModule,
    tiny_cpu_trainer,
)

_MIXTURE_ATTENTION_TYPE = MixtureOfAttentionHeadsConfig().registry_owner()
_MIXTURE_OF_EXPERTS_TYPE = MixtureOfExpertsModelConfig().registry_owner()
_MIXTURE_OF_EXPERTS_LAYER_TYPE = MixtureOfExpertsConfig().registry_owner()
_SELF_ATTENTION_TYPE = SelfAttentionConfig().registry_owner()
_TRANSFORMER_DECODER_LAYER_TYPE = TransformerDecoderLayerConfig().registry_owner()


class TestGptExpertLinearAdaptiveModel(unittest.TestCase):
    backend_module_name = "AdaptiveLinearLayer"

    def test_runtime_defaults_describe_a_gpt2_decoder_block(self):
        self.assertEqual(
            config.LAYER_NORM_POSITION,
            LayerNormPositionOptions.BEFORE,
        )
        self.assertFalse(config.EMBEDDING_LAYER_NORM_FLAG)
        self.assertEqual(config.FF_NUM_LAYERS, 1)
        self.assertEqual(config.ATTN_STACK_ACTIVATION, ActivationOptions.DISABLED)
        self.assertFalse(config.ATTN_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG)
        self.assertEqual(
            config.FF_STACK_LAYER_NORM_POSITION,
            LayerNormPositionOptions.DISABLED,
        )
        self.assertFalse(config.FF_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG)

    def config(self, **overrides):
        runtime = model_package("gpt/expert_linear_adaptive").bind_runtime_defaults(
            {
                "input_dim": 16,
                "output_dim": 16,
                "sequence_length": 6,
                **overrides,
            }
        )
        return GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_explicit_zero_prefix_selects_full_gradient_smooth_handoff(self):
        model_config = self.config(
            recurrent_flag=True,
            recurrent_max_steps=10,
            recurrent_initial_iterations=2,
            recurrent_no_gradient_transition_count=0,
            recurrent_gradient_transition_count=None,
            recurrent_iteration_increment=1,
            recurrent_forward_calls_before_iteration_increment=20_000,
            recurrent_smooth_iteration_growth_flag=True,
            recurrent_stack_halting_flag=True,
            recurrent_min_steps=2,
        )
        recurrent_config = model_config.experiment_config.decoder_config
        self.assertIsInstance(recurrent_config, RecurrentLayerConfig)
        recurrent_model = recurrent_config.build()
        schedule = recurrent_model.recurrent_iteration_schedule
        schedule.forward_call_progress.fill_(20_000)

        self.assertEqual(recurrent_config.no_gradient_transition_count, 0)
        self.assertIsInstance(recurrent_config.halting_config, StickBreakingConfig)
        self.assertEqual(recurrent_config.halting_config.min_steps, 2)
        self.assertEqual(
            type(schedule.execution_plan()).__name__,
            "RecurrentNestedSmoothHandoffExecutionPlan",
        )

    def test_public_imports_and_catalog_identity(self):
        self.assertTrue(issubclass(Model, LanguageModelExperiment))
        self.assertIsNotNone(Experiment)
        self.assertIsNotNone(ExperimentConfig)
        self.assertIsNotNone(ExperimentPresets)
        self.assertEqual(
            model_package("gpt/expert_linear_adaptive").catalog_key,
            "gpt/expert_linear_adaptive",
        )

    def test_cli_accepts_recurrent_minimum_and_ponder_cost_weight(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        parser = get_experiment_parser(package)
        args = parser.parse_args(
            [
                "--preset",
                "baseline",
                "--recurrent-flag",
                "true",
                "--recurrent-stack-halting-flag",
                "true",
                "--recurrent-min-steps",
                "3",
                "--recurrent-ponder-cost-weight",
                "1.0",
            ]
        )
        selection = resolve_cli_selection(args, package, ExperimentPreset)
        runtime = package.bind_runtime_defaults(selection.config_overrides)

        built = GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

        recurrent = built.experiment_config.decoder_config
        self.assertIsInstance(recurrent, RecurrentLayerConfig)
        self.assertFalse(hasattr(recurrent, "min_steps"))
        self.assertEqual(recurrent.halting_config.min_steps, 3)
        self.assertEqual(recurrent.halting_config.ponder_cost_weight, 1.0)

    def test_recurrent_minimum_requires_recurrent_halting(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        parser = get_experiment_parser(package)
        args = parser.parse_args(
            [
                "--preset",
                "baseline",
                "--recurrent-flag",
                "true",
                "--recurrent-stack-halting-flag",
                "false",
                "--recurrent-min-steps",
                "3",
            ]
        )
        selection = resolve_cli_selection(args, package, ExperimentPreset)
        runtime = package.bind_runtime_defaults(selection.config_overrides)

        with self.assertRaisesRegex(
            ValueError,
            "recurrent_min_steps.*recurrent_stack_halting_flag",
        ):
            GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_recurrent_minimum_requires_recurrence(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        runtime = package.bind_runtime_defaults(
            {
                "recurrent_flag": False,
                "recurrent_min_steps": 3,
            }
        )

        with self.assertRaisesRegex(
            ValueError,
            "recurrent_min_steps.*recurrent_flag",
        ):
            GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_recurrent_minimum_rejects_wrong_types_during_runtime_binding(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        invalid_values = (True, 1.5, "1")

        for invalid_value in invalid_values:
            with self.subTest(invalid_value=invalid_value):
                with self.assertRaisesRegex(TypeError, "recurrent_min_steps"):
                    package.bind_runtime_defaults(
                        {"recurrent_min_steps": invalid_value}
                    )

    def test_recurrent_minimum_rejects_nonpositive_values_in_builder(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None

        for invalid_value in (0, -1):
            with self.subTest(invalid_value=invalid_value):
                runtime = package.bind_runtime_defaults(
                    {"recurrent_min_steps": invalid_value}
                )

                with self.assertRaisesRegex(ValueError, "recurrent_min_steps"):
                    GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_recurrent_minimum_cannot_exceed_recurrent_maximum(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        runtime = package.bind_runtime_defaults(
            {
                "recurrent_flag": True,
                "recurrent_stack_halting_flag": True,
                "recurrent_min_steps": 4,
                "recurrent_max_steps": 3,
            }
        )

        with self.assertRaisesRegex(
            ValueError,
            "recurrent_min_steps.*recurrent_max_steps",
        ):
            GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_recurrent_ponder_weight_rejects_wrong_types_during_runtime_binding(
        self,
    ):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        invalid_values = (True, "1.0")

        for invalid_value in invalid_values:
            with self.subTest(invalid_value=invalid_value):
                with self.assertRaisesRegex(
                    TypeError,
                    "recurrent_ponder_cost_weight",
                ):
                    package.bind_runtime_defaults(
                        {"recurrent_ponder_cost_weight": invalid_value}
                    )

    def test_recurrent_ponder_weight_rejects_invalid_values_in_builder(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        invalid_values = (
            float("nan"),
            float("inf"),
            float("-inf"),
            -0.1,
        )

        for invalid_value in invalid_values:
            with self.subTest(invalid_value=invalid_value):
                runtime = package.bind_runtime_defaults(
                    {"recurrent_ponder_cost_weight": invalid_value}
                )

                with self.assertRaisesRegex(
                    ValueError,
                    "recurrent_ponder_cost_weight",
                ):
                    GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_non_default_recurrent_ponder_weight_requires_recurrent_halting(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        runtime = package.bind_runtime_defaults(
            {
                "recurrent_flag": True,
                "recurrent_stack_halting_flag": False,
                "recurrent_ponder_cost_weight": 0.5,
            }
        )

        with self.assertRaisesRegex(
            ValueError,
            "recurrent_ponder_cost_weight.*recurrent_stack_halting_flag",
        ):
            GptExpertLinearAdaptiveConfigBuilder(runtime=runtime).build()

    def test_recurrent_controls_are_inspectable_and_serializable(self):
        package = model_package("gpt/expert_linear_adaptive")
        self.assertIsNotNone(package)
        assert package is not None
        fields = {field.key: field for field in configuration_schema(package).fields}

        minimum = fields["RECURRENT_MIN_STEPS"]
        self.assertEqual(minimum.flag, "--recurrent-min-steps")
        self.assertEqual(
            minimum.section_path,
            ("Recurrent Layer Options", "Recurrent Halting Options"),
        )
        self.assertEqual(minimum.value_type, "int")
        self.assertEqual(minimum.default, 1)

        ponder_weight = fields["RECURRENT_PONDER_COST_WEIGHT"]
        self.assertEqual(
            ponder_weight.flag,
            "--recurrent-ponder-cost-weight",
        )
        self.assertEqual(
            ponder_weight.section_path,
            ("Recurrent Layer Options", "Recurrent Halting Options"),
        )
        self.assertEqual(ponder_weight.value_type, "float")
        self.assertEqual(ponder_weight.default, 1.0)
        self.assertEqual(
            serialize_overrides(
                package,
                {
                    "recurrent_min_steps": "3",
                    "recurrent-ponder-cost-weight": "0.5",
                },
            ),
            {
                "RECURRENT_MIN_STEPS": 3,
                "RECURRENT_PONDER_COST_WEIGHT": 0.5,
            },
        )

    def test_presets_are_contiguous_buildable_and_always_causal(self):
        presets = model_package("gpt/expert_linear_adaptive").presets
        self.assertNotIn("CAUSAL", ExperimentPreset.__members__)
        self.assertEqual(
            [preset.value for preset in ExperimentPreset],
            list(range(1, len(ExperimentPreset) + 1)),
        )
        for preset in ExperimentPreset:
            with self.subTest(preset=preset.name):
                configs = (
                    presets.get_config(preset, WikiText103Hierarchical)
                    if preset is ExperimentPreset.HIERARCHICAL
                    else presets.get_config(preset)
                )
                self.assertTrue(configs)
                decoder_config = configs[0].experiment_config.decoder_config
                block_config = getattr(decoder_config, "block_config", decoder_config)
                layer_config = block_config.layer_config.layer_model_config
                self.assertTrue(
                    layer_config.self_attention_config.causal_attention_mask_flag
                )
                self.assertIsNone(layer_config.cross_attention_config)

    def test_forward_shape_tied_head_and_backend_construction(self):
        model = Model(self.config()).eval()
        input_ids = torch.tensor([[1, 2, 3, 4], [4, 3, 2, 1]])
        logits, auxiliary_loss = model(input_ids)

        self.assertEqual(tuple(logits.shape), (2, 4, 16))
        self.assertEqual(tuple(auxiliary_loss.shape), ())
        self.assertIs(model.lm_head.weight, model.token_embedding.weight)
        self.assertIsNone(model.lm_head.bias)
        self.assertIn(
            self.backend_module_name,
            {type(module).__name__ for module in model.modules()},
        )
        self.assertIn(
            "MixtureOfExperts",
            {type(module).__name__ for module in model.modules()},
        )
        decoder_layers = [
            module
            for module in model.modules()
            if isinstance(module, _TRANSFORMER_DECODER_LAYER_TYPE)
        ]
        self.assertTrue(decoder_layers)
        self.assertTrue(
            all(layer.cross_attention_model is None for layer in decoder_layers)
        )

    def test_lm_head_options_allow_untied_biased_projection(self):
        cfg = self.config(
            lm_head_weight_tying_flag=False,
            lm_head_bias_flag=True,
        )
        model = Model(cfg)
        self.assertIsNot(model.lm_head.weight, model.token_embedding.weight)
        self.assertIsNotNone(model.lm_head.bias)

    def test_tied_head_rejects_unequal_vocabularies(self):
        with self.assertRaises(ValueError):
            self.config(
                input_dim=15,
                output_dim=16,
                sequence_length=4,
            )

    def test_future_tokens_do_not_change_earlier_logits(self):
        torch.manual_seed(7)
        model = Model(self.config()).eval()
        original = torch.tensor([[1, 2, 3, 4, 5]])
        changed_future = torch.tensor([[1, 2, 3, 9, 10]])

        with torch.no_grad():
            original_logits, _ = model(original)
            changed_logits, _ = model(changed_future)

        torch.testing.assert_close(
            original_logits[:, :3],
            changed_logits[:, :3],
            rtol=1e-5,
            atol=1e-5,
        )

    def test_training_loss_has_gradient_flow(self):
        torch.manual_seed(11)
        model = Model(self.config())
        input_ids = torch.tensor([[1, 2, 3], [3, 4, 5]])
        labels = torch.tensor([[2, 3, 4], [4, 5, 6]])
        loss = model._model_step((input_ids, labels))
        loss.backward()
        gradients = [
            parameter.grad
            for parameter in model.parameters()
            if parameter.requires_grad and parameter.grad is not None
        ]
        self.assertTrue(gradients)
        self.assertTrue(any(torch.any(gradient.abs() > 0) for gradient in gradients))

    def test_generate_is_greedy_deterministic_and_restores_mode(self):
        torch.manual_seed(13)
        model = Model(self.config())
        prompt = torch.tensor([[1, 2, 3]])
        model.eval()
        with torch.no_grad():
            prompt_logits, _ = model(prompt)
        expected_next = prompt_logits[:, -1].argmax(dim=-1)

        model.train()
        first = model.generate(prompt, max_new_tokens=1)
        second = model.generate(prompt, max_new_tokens=1)

        self.assertTrue(model.training)
        self.assertEqual(tuple(first.shape), (1, 4))
        torch.testing.assert_close(first[:, :3], prompt)
        torch.testing.assert_close(first[:, -1], expected_next)
        torch.testing.assert_close(first, second)

    def test_generate_rejects_invalid_requests(self):
        model = Model(self.config())
        invalid_cases = (
            (torch.tensor([1, 2]), 1, (ValueError, TypeError)),
            (torch.empty((1, 0), dtype=torch.long), 1, (ValueError,)),
            (torch.tensor([[1, -1]]), 1, (ValueError,)),
            (torch.tensor([[1, 16]]), 1, (ValueError,)),
            (torch.tensor([[1, 2]]), -1, (ValueError,)),
            (torch.tensor([[1, 2]]), 5, (ValueError,)),
        )
        for input_ids, max_new_tokens, errors in invalid_cases:
            with self.subTest(
                shape=tuple(input_ids.shape),
                max_new_tokens=max_new_tokens,
            ):
                with self.assertRaises(errors):
                    model.generate(input_ids, max_new_tokens)

    def test_all_public_modules_import_and_catalog_resolves(self):
        for module_name in (
            "models.gpt.expert_linear_adaptive.config",
            "models.gpt.expert_linear_adaptive.presets",
            "models.gpt.expert_linear_adaptive.model",
            "models.gpt.expert_linear_adaptive.config_builder",
            "models.gpt.expert_linear_adaptive.experiment_config",
        ):
            with self.subTest(module_name=module_name):
                self.assertEqual(
                    importlib.import_module(module_name).__name__,
                    module_name,
                )
        experiment = Experiment(
            model_package=model_package("gpt/expert_linear_adaptive")
        )
        self.assertEqual(
            experiment.model_package.identity.catalog_key,
            "gpt/expert_linear_adaptive",
        )
        self.assertIsNotNone(model_package("gpt/expert_linear_adaptive"))

    def test_package_avoids_bert_and_gpt_sibling_construction_imports(self):
        package_dir = Path(config.__file__).resolve().parent
        blocked = (
            "models.bert.",
            "models.gpt.linear.",
            "models.gpt.linear_adaptive.",
            "models.gpt.expert_linear.",
        )
        for path in package_dir.glob("*.py"):
            if path.name == "test_model.py":
                continue
            source = path.read_text(encoding="utf-8")
            for import_path in blocked:
                with self.subTest(path=path.name, import_path=import_path):
                    self.assertNotIn(import_path, source)

    def test_builder_removes_attention_and_causal_switches(self):
        parameters = inspect.signature(GptExpertLinearAdaptiveConfigBuilder).parameters
        self.assertNotIn("expert_attention_flag", parameters)
        self.assertNotIn("causal_attention_mask_flag", parameters)
        self.assertEqual(tuple(parameters), ("runtime",))
        model_package("gpt/expert_linear_adaptive").bind_runtime_defaults(
            {"expert_attention_use_kv_expert_models_flag": False}
        )
        self.assertFalse(hasattr(config, "EXPERT_ATTENTION_FLAG"))
        self.assertFalse(hasattr(config, "CAUSAL_ATTENTION_MASK_FLAG"))
        with self.assertRaises(TypeError):
            GptExpertLinearAdaptiveConfigBuilder(expert_attention_flag=False)
        with self.assertRaises(TypeError):
            GptExpertLinearAdaptiveConfigBuilder(causal_attention_mask_flag=False)

    def test_low_rank_preset_uses_adaptive_expert_layers(self):
        cfg = self._preset_config(ExperimentPreset.LOW_RANK_EXPERT_WEIGHT)
        mixture = self._decoder_layer_config(cfg).feed_forward_config.stack_config
        expert_core = mixture.stack_config.layer_config.layer_model_config
        expert_layer = expert_core.expert_model_config.layer_config.layer_model_config
        self.assertIsInstance(mixture, MixtureOfExpertsModelConfig)
        self.assertIsInstance(expert_layer, AdaptiveLinearLayerConfig)
        self.assertIsNotNone(expert_layer.adaptive_augmentation_config.weight_config)

    def test_single_layer_recurrent_attention_residual_preset(self):
        cfg = self._preset_config(
            ExperimentPreset.SINGLE_LAYER_RECURRENT_ATTENTION_RESIDUAL
        )

        recurrent_config = cfg.experiment_config.decoder_config
        self.assertIsInstance(recurrent_config, RecurrentLayerConfig)
        self.assertEqual(recurrent_config.input_dim, 32)
        self.assertEqual(cfg.sequence_length, 35)
        self.assertEqual(recurrent_config.max_steps, 10)
        self.assertFalse(hasattr(recurrent_config, "min_steps"))
        self.assertEqual(recurrent_config.halting_config.min_steps, 1)
        self.assertEqual(recurrent_config.block_config.num_layers, 1)
        self.assertEqual(recurrent_config.halting_config.threshold, 0.99)
        self.assertEqual(
            recurrent_config.halting_config.ponder_cost_weight,
            1.0,
        )
        self.assertEqual(
            recurrent_config.halting_config.hidden_state_mode,
            config.HaltingHiddenStateModeOptions.RAW,
        )
        self.assertIsInstance(
            recurrent_config.residual_config,
            AttentionResidualConfig,
        )
        self.assertIsInstance(recurrent_config.halting_config, StickBreakingConfig)

        decoder_layer = recurrent_config.block_config.layer_config.layer_model_config
        feed_forward_mixture = decoder_layer.feed_forward_config.stack_config
        expert_core = feed_forward_mixture.stack_config.layer_config.layer_model_config
        expert_layer = expert_core.expert_model_config.layer_config.layer_model_config
        adaptive_config = expert_layer.adaptive_augmentation_config

        self.assertEqual(decoder_layer.dropout_probability, 0.0)
        self.assertEqual(decoder_layer.self_attention_config.num_heads, 4)
        self.assertFalse(decoder_layer.self_attention_config.use_kv_expert_models_flag)
        self.assertEqual(
            decoder_layer.self_attention_config.experts_config.capacity_factor,
            0.0,
        )
        self.assertEqual(feed_forward_mixture.stack_config.hidden_dim, 32)
        self.assertEqual(expert_core.num_experts, 12)
        self.assertEqual(expert_core.top_k, 2)
        self.assertEqual(expert_core.capacity_factor, 0.0)
        self.assertEqual(expert_core.sampler_config.switch_loss_weight, 0.01)
        self.assertEqual(expert_core.sampler_config.zero_centred_loss_weight, 0.001)
        self.assertEqual(
            decoder_layer.self_attention_config.experts_config.num_experts, 12
        )
        self.assertEqual(decoder_layer.self_attention_config.experts_config.top_k, 2)
        self.assertTrue(expert_layer.bias_flag)
        self.assertIsInstance(
            adaptive_config.weight_config,
            SingleModelDynamicWeightConfig,
        )
        self.assertEqual(
            adaptive_config.weight_config.generator_depth,
            5,
        )
        self.assertEqual(
            adaptive_config.weight_config.normalization_option,
            WeightNormalizationOptions.L2_SCALE,
        )
        self.assertEqual(
            adaptive_config.weight_config.normalization_position_option,
            WeightNormalizationPositionOptions.AFTER_OUTER_PRODUCT,
        )
        self.assertEqual(
            adaptive_config.weight_config.decay_schedule,
            WeightDecayScheduleOptions.EXPONENTIAL,
        )
        self.assertEqual(adaptive_config.weight_config.decay_rate, 1e-4)
        self.assertEqual(adaptive_config.weight_config.decay_warmup_batches, 5_000)
        self.assertIsInstance(
            adaptive_config.bias_config,
            GeneratorDynamicBiasConfig,
        )
        self.assertIsInstance(
            adaptive_config.diagonal_config,
            CombinedDynamicDiagonalConfig,
        )
        self.assertIsNone(adaptive_config.mask_config)

        model = Model(cfg).eval()
        self.assertIsInstance(
            model.transformer.residual_connection,
            recurrent_config.residual_config.registry_owner(),
        )
        self.assertIsInstance(
            model.transformer.halting_model,
            recurrent_config.halting_config.registry_owner(),
        )
        logits, auxiliary_loss = model(self._input_ids(cfg))
        self.assertEqual(
            tuple(logits.shape),
            (2, cfg.sequence_length, cfg.output_dim),
        )
        self.assertEqual(tuple(auxiliary_loss.shape), ())

    @pytest.mark.training
    def test_single_layer_recurrent_attention_residual_preset_trains_one_batch(self):
        torch.manual_seed(449)
        cfg = self._preset_config(
            ExperimentPreset.SINGLE_LAYER_RECURRENT_ATTENTION_RESIDUAL
        )
        model = Model(cfg)
        parameters_before_training = {
            name: parameter.detach().clone()
            for name, parameter in model.named_parameters()
            if parameter.requires_grad
        }
        trainer = tiny_cpu_trainer()

        trainer.fit(
            model,
            datamodule=RandomLanguageModelDataModule(
                cfg,
                batch_size=2,
                num_batches=1,
            ),
        )

        self.assertEqual(trainer.global_step, 1)
        self.assertTrue(torch.isfinite(trainer.callback_metrics["train/loss"]).item())
        self.assertTrue(
            any(
                not torch.equal(parameter.detach(), parameters_before_training[name])
                for name, parameter in model.named_parameters()
                if parameter.requires_grad
            )
        )
        self.assertTrue(
            all(
                torch.isfinite(parameter).all().item()
                for parameter in model.parameters()
            )
        )

    def test_expert_attention_uses_adaptive_expert_internals(self):
        cfg = self._preset_config(ExperimentPreset.BASELINE)
        attention = self._decoder_layer_config(cfg).self_attention_config
        expert_stack = attention.experts_config.expert_model_config
        expert_layer = expert_stack.layer_config.layer_model_config
        self.assertIsInstance(attention, MixtureOfAttentionHeadsConfig)
        self.assertIsInstance(expert_layer, AdaptiveLinearLayerConfig)

    def test_ff_controls_apply_to_outer_slot_and_preserve_adaptive_experts(self):
        cfg = self._preset_config(
            ExperimentPreset.LOW_RANK_EXPERT_WEIGHT,
            {
                "ff_stack_hidden_dim": 17,
                "ff_stack_gate_flag": True,
                "expert_stack_hidden_dim": 11,
            },
        )
        mixture = self._decoder_layer_config(cfg).feed_forward_config.stack_config
        outer = mixture.stack_config
        expert_stack = outer.layer_config.layer_model_config.expert_model_config
        expert_layer = expert_stack.layer_config.layer_model_config
        self.assertEqual(outer.hidden_dim, 17)
        self.assertIsNotNone(outer.layer_config.gate_config)
        self.assertEqual(expert_stack.hidden_dim, 11)
        self.assertIsInstance(expert_layer, AdaptiveLinearLayerConfig)
        self.assertIsNotNone(expert_layer.adaptive_augmentation_config.weight_config)

    def test_attention_controls_preserve_adaptive_expert_attention(self):
        cfg = self._preset_config(
            ExperimentPreset.BASELINE,
            {
                "weight_option_flag": True,
                "weight_option": config.LowRankDynamicWeightConfig,
                "attn_stack_hidden_dim": 17,
                "attn_stack_gate_flag": True,
                "expert_stack_hidden_dim": 11,
            },
        )
        attention = self._decoder_layer_config(cfg).self_attention_config
        projection = attention.projection_model_config
        expert_stack = attention.experts_config.expert_model_config
        expert_layer = expert_stack.layer_config.layer_model_config
        self.assertEqual(projection.hidden_dim, 17)
        self.assertIsNotNone(projection.layer_config.gate_config)
        self.assertEqual(expert_stack.hidden_dim, 11)
        self.assertIsNone(expert_stack.layer_config.gate_config)
        self.assertIsInstance(expert_layer, AdaptiveLinearLayerConfig)
        self.assertIsNotNone(expert_layer.adaptive_augmentation_config.weight_config)

    def test_dense_attention_kv_uses_the_expert_adaptive_augmentation(self):
        cfg = self._preset_config(
            ExperimentPreset.BASELINE,
            {
                "expert_attention_use_kv_expert_models_flag": False,
                "weight_option_flag": True,
                "weight_option": config.LowRankDynamicWeightConfig,
            },
        )
        attention_config = self._decoder_layer_config(cfg).self_attention_config
        expert_stack = attention_config.experts_config.expert_model_config
        expert_layer = expert_stack.layer_config.layer_model_config
        dense_kv_stack = attention_config.projection_model_config
        dense_kv_layer = dense_kv_stack.layer_config.layer_model_config

        self.assertIsInstance(expert_layer, AdaptiveLinearLayerConfig)
        self.assertIsInstance(dense_kv_layer, AdaptiveLinearLayerConfig)
        self.assertEqual(
            dense_kv_layer.adaptive_augmentation_config,
            expert_layer.adaptive_augmentation_config,
        )

        model = Model(cfg)
        logits, auxiliary_loss = model(self._input_ids(cfg))
        (logits.square().mean() + auxiliary_loss).backward()
        attention = next(
            module
            for module in model.modules()
            if isinstance(module, _MIXTURE_ATTENTION_TYPE)
        )
        self.assertFalse(attention.cfg.use_kv_expert_models_flag)
        for role, projection_model in {
            "key": attention.projector.key_model,
            "value": attention.projector.value_model,
        }.items():
            with self.subTest(role=role):
                self.assertNotIsInstance(
                    projection_model,
                    _MIXTURE_OF_EXPERTS_LAYER_TYPE,
                )
                adaptive_layers = tuple(
                    module
                    for module in projection_model.modules()
                    if type(module).__name__ == "AdaptiveLinearLayer"
                )
                self.assertTrue(adaptive_layers)
                self.assertTrue(
                    all(layer.has_adaptive_augmentation for layer in adaptive_layers)
                )
                self._assert_nonzero_parameter_gradients(projection_model, role)

    def test_every_preset_forwards_adaptive_moe_and_mixture_attention(self):
        for preset in ExperimentPreset:
            if preset is ExperimentPreset.HIERARCHICAL:
                # Typed raw-text execution has its own complete-path suite.
                continue
            with self.subTest(preset=preset.name):
                cfg = self._preset_config(preset)
                model = Model(cfg)
                logits, auxiliary_loss = model(self._input_ids(cfg))
                modules = tuple(model.modules())
                self.assertTrue(
                    any(isinstance(m, _MIXTURE_ATTENTION_TYPE) for m in modules)
                )
                self.assertTrue(
                    any(isinstance(m, _MIXTURE_OF_EXPERTS_TYPE) for m in modules)
                )
                self.assertTrue(
                    any(type(m).__name__ == "AdaptiveLinearLayer" for m in modules)
                )
                self.assertFalse(
                    any(isinstance(m, _SELF_ATTENTION_TYPE) for m in modules)
                )
                self.assertEqual(
                    tuple(logits.shape),
                    (2, cfg.sequence_length, cfg.output_dim),
                )
                self.assertEqual(tuple(auxiliary_loss.shape), ())
                self.assertTrue(torch.isfinite(logits).all())
                self.assertTrue(torch.isfinite(auxiliary_loss))

    def test_attention_kv_modes_forward_backward(self):
        cases = (
            ("regular_kv", ExperimentPreset.BASELINE, False, False),
            ("expert_kv", ExperimentPreset.BASELINE, True, False),
            ("expert_kv_bias", ExperimentPreset.ATTENTION_BIAS, True, True),
        )
        for name, preset, use_kv_experts, expect_bias in cases:
            with self.subTest(name=name):
                torch.manual_seed(0)
                cfg = self._preset_config(
                    preset,
                    {"expert_attention_use_kv_expert_models_flag": (use_kv_experts)},
                )
                model = Model(cfg)
                logits, auxiliary_loss = model(self._input_ids(cfg))
                attention = next(
                    m for m in model.modules() if isinstance(m, _MIXTURE_ATTENTION_TYPE)
                )
                self.assertEqual(
                    attention.cfg.use_kv_expert_models_flag,
                    use_kv_experts,
                )
                self.assertEqual(
                    attention.cfg.add_key_value_bias_flag,
                    expect_bias,
                )
                (logits.square().mean() + auxiliary_loss).backward()
                self._assert_nonzero_parameter_gradients(
                    model.token_embedding,
                    "token embedding",
                )
                projector = attention.projector
                if use_kv_experts:
                    for role, expert_model in {
                        "key": projector.key_model,
                        "value": projector.value_model,
                    }.items():
                        with self.subTest(name=name, role=role):
                            self.assertIsInstance(
                                expert_model, _MIXTURE_OF_EXPERTS_LAYER_TYPE
                            )
                            self._assert_nonzero_parameter_gradients(
                                expert_model,
                                role,
                            )
                else:
                    self._assert_nonzero_parameter_gradients(
                        projector.key_model,
                        "regular key projection",
                    )
                    self._assert_nonzero_parameter_gradients(
                        projector.value_model,
                        "regular value projection",
                    )
                if expect_bias:
                    self.assertGreater(
                        attention.bias.key_bias_vector.grad.abs().sum().item(),
                        0.0,
                    )
                    self.assertGreater(
                        attention.bias.value_bias_vector.grad.abs().sum().item(),
                        0.0,
                    )

    def test_routed_auxiliary_loss_is_added_to_cross_entropy(self):
        torch.manual_seed(0)
        cfg = self._preset_config(ExperimentPreset.TOP1_SWITCH_AUX)
        model = Model(cfg)
        inputs = self._input_ids(cfg)
        labels = torch.roll(inputs, shifts=-1, dims=1)
        output = model._model_step_outputs((inputs, labels))
        self.assertGreater(output.auxiliary_loss.item(), 0.0)
        torch.testing.assert_close(
            output.total_loss,
            output.cross_entropy + output.auxiliary_loss,
        )

    def test_forward_runs_one_decoder_pass_and_leaves_causality_to_attention(self):
        cfg = self._preset_config(ExperimentPreset.BASELINE)
        model = Model(cfg)

        class SpyDecoder(nn.Module):
            def __init__(self):
                super().__init__()
                self.state = None
                self.calls = 0

            def forward(self, state):
                self.calls += 1
                self.state = state
                state.loss = state.hidden.new_zeros(())
                return state

        spy = SpyDecoder()
        model.transformer = spy
        input_ids = self._input_ids(cfg)
        attention_mask = torch.ones_like(input_ids)
        attention_mask[:, -1] = 0
        model(input_ids, attention_mask)
        self.assertEqual(spy.calls, 1)
        self.assertIsInstance(spy.state, TransformerDecoderLayerState)
        torch.testing.assert_close(
            spy.state.target_key_padding_mask,
            attention_mask == 0,
        )
        self.assertIsNone(spy.state.target_attention_mask)

    def test_boundary_options_are_plain_and_fully_configurable(self):
        defaults = self._default_builder()
        cfg = self._direct_config(
            embedding_options=replace(
                defaults.embedding_options,
                layer_norm_flag=False,
                dropout_probability=0.25,
            ),
            lm_head_options=replace(
                defaults.lm_head_options,
                weight_tying_flag=False,
                bias_flag=True,
            ),
        )
        model = Model(cfg)
        self.assertIsInstance(model.token_embedding, nn.Embedding)
        self.assertIsInstance(model.lm_head, nn.Linear)
        self.assertIsInstance(model.embedding_layer_norm, nn.Identity)
        self.assertEqual(model.embedding_dropout.p, 0.25)
        self.assertIsNot(model.lm_head.weight, model.token_embedding.weight)
        self.assertIsNotNone(model.lm_head.bias)

    def test_untied_head_allows_mismatched_vocabularies(self):
        defaults = self._default_builder()
        cfg = self._direct_config(
            input_dim=29,
            output_dim=31,
            lm_head_options=replace(
                defaults.lm_head_options,
                weight_tying_flag=False,
            ),
        )
        logits, _ = Model(cfg)(self._input_ids(cfg))
        self.assertEqual(logits.shape[-1], 31)
        with self.assertRaisesRegex(ValueError, "weight tying.*input_dim.*output_dim"):
            self._direct_config(input_dim=29, output_dim=31)

    def test_invalid_dimensions_and_dropout_are_rejected(self):
        defaults = self._default_builder()
        cases = {
            "input_dim": {"input_dim": 0},
            "hidden_dim": {
                "decoder_options": replace(
                    defaults.decoder_options,
                    hidden_dim=0,
                )
            },
            "output_dim": {
                "output_dim": 0,
                "lm_head_options": replace(
                    defaults.lm_head_options,
                    weight_tying_flag=False,
                ),
            },
            "sequence_length": {"sequence_length": 0},
        }
        for field, overrides in cases.items():
            with self.subTest(field=field):
                with self.assertRaisesRegex(ValueError, field):
                    self._direct_config(**overrides)
        for probability in (-0.01, 1.01):
            with self.subTest(probability=probability):
                with self.assertRaisesRegex(ValueError, "dropout_probability"):
                    self._direct_config(
                        embedding_options=replace(
                            defaults.embedding_options,
                            dropout_probability=probability,
                        )
                    )

    def test_baseline_forwards_both_language_model_datasets(self):
        for dataset in dataset_options.DATASET_OPTIONS_BY_TASK[
            dataset_options.DEFAULT_EXPERIMENT_TASK
        ]:
            if getattr(dataset, "hierarchical_language_model_flag", False):
                with self.assertRaises(ValueError):
                    model_package("gpt/expert_linear_adaptive").presets.get_config(
                        ExperimentPreset.BASELINE, dataset
                    )
                continue
            with self.subTest(dataset=dataset.__name__):
                overrides = self._small_flat_overrides()
                overrides.pop("input_dim")
                overrides.pop("output_dim")
                cfg = model_package("gpt/expert_linear_adaptive").presets.get_config(
                    ExperimentPreset.BASELINE,
                    dataset,
                    config_overrides=overrides,
                )[0]
                logits, auxiliary_loss = Model(cfg)(self._input_ids(cfg))
                self.assertEqual(logits.shape[-1], dataset.num_classes)
                self.assertEqual(tuple(auxiliary_loss.shape), ())

    @pytest.mark.training
    def test_representative_presets_train_tiny_epochs(self):
        for preset in (
            ExperimentPreset.BASELINE,
            ExperimentPreset.LOW_RANK_EXPERT_WEIGHT,
        ):
            with self.subTest(preset=preset.name):
                cfg = self._preset_config(preset)
                tiny_cpu_trainer().fit(
                    Model(cfg),
                    datamodule=RandomLanguageModelDataModule(
                        cfg,
                        batch_size=2,
                        num_batches=1,
                    ),
                )

    def _preset_config(
        self,
        preset: ExperimentPreset,
        overrides: dict | None = None,
    ):
        small_overrides = self._small_flat_overrides()
        if preset is ExperimentPreset.SINGLE_LAYER_RECURRENT_ATTENTION_RESIDUAL:
            for preset_field in (
                "hidden_dim",
                "sequence_length",
                "stack_num_layers",
                "attn_num_heads",
                "stack_dropout_probability",
                "num_experts",
                "recurrent_max_steps",
            ):
                small_overrides.pop(preset_field)
        configuration = model_package("gpt/expert_linear_adaptive").presets.get_config(
            preset,
            dataset_options.DATASET_OPTIONS_BY_TASK[
                dataset_options.DEFAULT_EXPERIMENT_TASK
            ][0],
            config_overrides={
                **(
                    {
                        "recurrent_residual_block_size": 1,
                        "recurrent_residual_rms_norm_epsilon": 1e-6,
                    }
                    if preset
                    is ExperimentPreset.SINGLE_LAYER_RECURRENT_ATTENTION_RESIDUAL
                    else {}
                ),
                **small_overrides,
                **(overrides or {}),
            },
        )[0]

        return configuration

    def _direct_config(
        self,
        *,
        embedding_options: GptEmbeddingOptions | None = None,
        decoder_options: TransformerDecoderOptions | None = None,
        lm_head_options: GptLmHeadOptions | None = None,
        **overrides,
    ):
        flat_overrides = {
            **self._small_flat_overrides(),
            **overrides,
        }
        if embedding_options is not None:
            flat_overrides.update(
                embedding_layer_norm_flag=embedding_options.layer_norm_flag,
                embedding_dropout_probability=embedding_options.dropout_probability,
            )
        if decoder_options is not None:
            flat_overrides.update(
                hidden_dim=decoder_options.hidden_dim,
                stack_num_layers=decoder_options.num_layers,
                stack_activation=decoder_options.activation,
                stack_dropout_probability=decoder_options.dropout_probability,
                layer_norm_position=decoder_options.layer_norm_position,
            )
        if lm_head_options is not None:
            flat_overrides.update(
                lm_head_weight_tying_flag=lm_head_options.weight_tying_flag,
                lm_head_bias_flag=lm_head_options.bias_flag,
            )
        return model_package("gpt/expert_linear_adaptive").build_configuration(
            config_overrides=flat_overrides
        )

    def _small_flat_overrides(self) -> dict:
        return {
            "batch_size": 2,
            "input_dim": 32,
            "output_dim": 32,
            "hidden_dim": 8,
            "sequence_length": 6,
            "stack_num_layers": 2,
            "attn_num_heads": 2,
            "stack_dropout_probability": 0.0,
            "num_experts": 4,
            "recurrent_max_steps": 2,
        }

    def _default_builder(self) -> GptExpertLinearAdaptiveConfigBuilder:
        runtime = model_package("gpt/expert_linear_adaptive").bind_runtime_defaults()
        return GptExpertLinearAdaptiveConfigBuilder(runtime=runtime)

    def _input_ids(self, cfg) -> torch.Tensor:
        return torch.randint(0, cfg.input_dim, (2, cfg.sequence_length))

    def _decoder_layer_config(self, cfg):
        decoder = cfg.experiment_config.decoder_config
        decoder = getattr(decoder, "block_config", decoder)
        return decoder.layer_config.layer_model_config

    def _assert_nonzero_parameter_gradients(self, model, role: str) -> None:
        gradients = [
            parameter.grad
            for parameter in model.parameters()
            if parameter.grad is not None
        ]
        self.assertTrue(gradients, f"{role} had no gradients")
        self.assertTrue(
            any(gradient.abs().sum().item() > 0.0 for gradient in gradients),
            f"{role} gradients were all zero",
        )


if __name__ == "__main__":
    unittest.main()
