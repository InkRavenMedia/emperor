from __future__ import annotations

# ruff: noqa: I001

import importlib
import os
import sys
import tempfile
import unittest
from pathlib import Path

os.environ.setdefault("MPLCONFIGDIR", "/tmp/matplotlib")

import models.linears.linear.config as linear_config
from emperor.layers import LayerGateOptions, WeightedResidualConfig
from emperor.layers import ActivationOptions
from emperor.memory import WeightedDynamicMemoryConfig
from model_runtime.packages.configuration_metadata import (
    configuration_field_metadata,
)
from models.catalog import discover_model_ids
from model_runtime.packages import ConfigValueError, parse_config_value

from tests.support.inspection import (
    config_schema,
    search_space_schema,
)


def _fields_by_key(payload: dict) -> dict[str, dict]:
    return {field["key"].lower(): field for field in payload["fields"]}


def _axes_by_key(payload: dict) -> dict[str, dict]:
    return {axis["key"].lower(): axis for axis in payload["axes"]}


class InspectorSchemaTests(unittest.TestCase):
    def test_gpt_schemas_remove_pretraining_and_causal_switch_fields(self) -> None:
        blocked = {
            "causal_attention_mask_flag",
            "token_type_vocab_size",
            "mlm_activation",
            "mlm_decoder_bias_flag",
            "nsp_output_dim",
        }
        for model_name in (
            "gpt/linear",
            "gpt/linear_adaptive",
            "gpt/expert_linear",
            "gpt/expert_linear_adaptive",
        ):
            with self.subTest(model_name=model_name):
                fields = _fields_by_key(config_schema(model_name))
                self.assertFalse(blocked & set(fields))
                self.assertFalse(any("causal" in key for key in fields))
                self.assertIn("sequence_length", fields)
                self.assertTrue(fields["lm_head_weight_tying_flag"]["default"])
                self.assertFalse(fields["lm_head_bias_flag"]["default"])
                self.assertIn("embedding_layer_norm_flag", fields)
                self.assertIn("embedding_dropout_probability", fields)

    def test_gpt_and_bert_search_axes_differ_in_task_normalization(self) -> None:
        for backend in (
            "linear",
            "linear_adaptive",
            "expert_linear",
            "expert_linear_adaptive",
        ):
            with self.subTest(backend=backend):
                gpt_axes = _axes_by_key(
                    search_space_schema(f"gpt/{backend}", "baseline")
                )
                bert_axes = _axes_by_key(
                    search_space_schema(f"bert/{backend}", "baseline")
                )
                self.assertEqual(
                    gpt_axes.keys() - bert_axes.keys(), {"decoder_output_normalization"}
                )
                self.assertEqual(
                    bert_axes.keys() - gpt_axes.keys(),
                    {"encoder_output_normalization", "mlm_normalization"},
                )

    def test_config_schema_emits_uppercase_public_keys(self) -> None:
        fields = config_schema("linears/linear")["fields"]

        stack_field = next(
            field
            for field in fields
            if field["configKey"] == "STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG"
        )
        self.assertEqual(stack_field["key"], "STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG")
        self.assertEqual(stack_field["key"], stack_field["configKey"])
        self.assertEqual(
            stack_field["flag"], "--stack-apply-output-postprocessing-flag"
        )
        for field in fields:
            self.assertEqual(field["key"], field["configKey"])
            self.assertTrue(field["key"].isupper())

    def test_config_schema_exposes_residual_model_flags(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear"))
        residual_model_flag = fields["stack_residual_model_flag"]
        residual_stack_hidden_dim = fields["residual_stack_hidden_dim"]

        self.assertEqual(
            residual_model_flag["configKey"],
            "STACK_RESIDUAL_MODEL_FLAG",
        )
        self.assertEqual(
            residual_model_flag["flag"],
            "--stack-residual-model-flag",
        )
        self.assertEqual(residual_model_flag["type"], "bool")
        self.assertIs(residual_model_flag["default"], False)
        self.assertFalse(residual_model_flag["nullable"])
        self.assertEqual(residual_model_flag["applicableWhen"], [])
        self.assertIn(
            "Residual Stack Options as a data-dependent query or coefficient model",
            residual_model_flag["description"],
        )
        self.assertEqual(
            residual_stack_hidden_dim["sectionPath"],
            ["Residual Options", "Residual Stack Options"],
        )
        self.assertEqual(
            residual_stack_hidden_dim["flag"],
            "--residual-stack-hidden-dim",
        )

    def test_config_schema_does_not_invent_recurrent_applicability(self) -> None:
        fields = _fields_by_key(config_schema("transformer/linear"))

        self.assertEqual(
            fields["recurrent_max_steps"]["applicableWhen"],
            [],
        )
        self.assertEqual(
            fields["attn_recurrent_initialization_standard_deviation"][
                "applicableWhen"
            ],
            [],
        )
        self.assertEqual(
            fields["ff_recurrent_no_gradient_transition_count"]["applicableWhen"],
            [],
        )
        self.assertEqual(
            _fields_by_key(config_schema("linears/linear"))["hidden_dim"][
                "applicableWhen"
            ],
            [],
        )

    def test_search_schema_emits_uppercase_axis_keys(self) -> None:
        axes = search_space_schema("linears/linear", "baseline")["axes"]

        stack_axis = next(
            axis for axis in axes if axis["searchKey"] == "SEARCH_SPACE_HIDDEN_DIM"
        )
        self.assertEqual(stack_axis["key"], "HIDDEN_DIM")
        self.assertEqual(stack_axis["key"], stack_axis["configKey"])
        self.assertEqual(stack_axis["searchKey"], "SEARCH_SPACE_HIDDEN_DIM")
        for axis in axes:
            self.assertEqual(axis["key"], axis["configKey"])
            self.assertTrue(axis["key"].isupper())

    def test_config_schema_excludes_dataset_monitor_and_search_modules(self) -> None:
        blocked_keys = {"DATASET_OPTIONS", "MONITOR_OPTIONS"}
        for model_name in discover_model_ids():
            with self.subTest(model_name=model_name):
                fields = config_schema(model_name)["fields"]
                field_keys = {field["key"] for field in fields}
                self.assertFalse(blocked_keys & field_keys)
                self.assertFalse(
                    any(field["key"].startswith("SEARCH_SPACE_") for field in fields)
                )

    def test_config_schema_sections_imported_trainer_defaults(self) -> None:
        with tempfile.TemporaryDirectory() as temp_dir:
            temp_path = Path(temp_dir)
            shared_module_name = "shared_trainer_config_fixture"
            model_module_name = "model_config_fixture"
            (temp_path / f"{shared_module_name}.py").write_text(
                "\n".join(
                    [
                        '"""Shared trainer defaults for schema tests."""',
                        "# Trainer",
                        "TRAINER_MAX_STEPS: int = -1",
                        "TRAINER_PRECISION: str = '32-true'",
                        "# Callback",
                        "CALLBACK_CHECKPOINT_FLAG: bool = False",
                    ]
                ),
                encoding="utf-8",
            )
            (temp_path / f"{model_module_name}.py").write_text(
                "\n".join(
                    [
                        f"from {shared_module_name} import *",
                        "",
                        "# Trainer",
                        "TRAINER_ACCELERATOR: str = 'cpu'",
                        "",
                        "# Model",
                        "HIDDEN_DIM: int = 128",
                    ]
                ),
                encoding="utf-8",
            )
            sys.path.insert(0, temp_dir)
            try:
                importlib.invalidate_caches()
                config_module = importlib.import_module(model_module_name)
                metadata = configuration_field_metadata(config_module)
            finally:
                sys.path.remove(temp_dir)
                sys.modules.pop(model_module_name, None)
                sys.modules.pop(shared_module_name, None)

        self.assertEqual(metadata["TRAINER_ACCELERATOR"]["section"], "Trainer")
        self.assertEqual(metadata["TRAINER_MAX_STEPS"]["section"], "Trainer")
        self.assertEqual(metadata["TRAINER_PRECISION"]["section"], "Trainer")
        self.assertEqual(metadata["CALLBACK_CHECKPOINT_FLAG"]["section"], "Callback")
        self.assertEqual(metadata["HIDDEN_DIM"]["section"], "Model")

    def test_config_schema_uses_markdown_heading_section_paths(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear"))

        self.assertEqual(
            fields["recurrent_gate_stack_hidden_dim"]["section"],
            "Recurrent Gate Stack Options",
        )
        self.assertEqual(
            fields["recurrent_gate_stack_hidden_dim"]["sectionPath"],
            [
                "Recurrent Layer Options",
                "Recurrent Gate Options",
                "Recurrent Gate Stack Options",
            ],
        )
        self.assertEqual(fields["data_num_workers"]["section"], "Run")
        self.assertEqual(fields["data_num_workers"]["sectionPath"], ["Run"])
        self.assertEqual(fields["run_test_after_fit"]["section"], "Run")

    def test_config_schema_requires_catalog_section_paths(self) -> None:
        forbidden_section_terms = ("Dataset", "Monitor", "Search", "General", "None")
        expected_paths = {
            "linears/linear": {
                "gate_stack_hidden_dim": [
                    "Gate Options",
                    "Gate Stack Options",
                ],
                "recurrent_gate_stack_hidden_dim": [
                    "Recurrent Layer Options",
                    "Recurrent Gate Options",
                    "Recurrent Gate Stack Options",
                ],
            },
            "experts/linear_adaptive": {
                "expert_recurrent_gate_stack_hidden_dim": [
                    "Mixture Of Experts Model Options",
                    "Expert Recurrent Layer Options",
                    "Expert Recurrent Gate Options",
                    "Expert Recurrent Gate Stack Options",
                ],
                "router_weight_generator_stack_hidden_dim": [
                    "Sampler Model Options",
                    "Router Options",
                    "Router Weight Generator Options",
                    "Router Weight Generator Stack Options",
                ],
            },
            "neuron/linear": {
                "cluster_terminal_router_hidden_dim": [
                    "Neuron Wrapper Options",
                    "Cluster Terminal Options",
                    "Cluster Terminal Router Options",
                ],
                "cluster_halting_stack_hidden_dim": [
                    "Neuron Wrapper Options",
                    "Cluster Halting Options",
                ],
            },
        }

        for model_name in discover_model_ids():
            with self.subTest(model_name=model_name):
                fields = _fields_by_key(config_schema(model_name))
                for field in fields.values():
                    self.assertTrue(field["sectionPath"], field["key"])
                    self.assertEqual(field["section"], field["sectionPath"][-1])
                    self.assertFalse(
                        any(
                            term in section
                            for section in field["sectionPath"]
                            for term in forbidden_section_terms
                        ),
                        (
                            f"{field['key']} uses forbidden sectionPath "
                            f"{field['sectionPath']}"
                        ),
                    )
                for field_key, expected_path in expected_paths.get(
                    model_name,
                    {},
                ).items():
                    self.assertEqual(fields[field_key]["sectionPath"], expected_path)

    def test_vit_schemas_hide_grouped_builder_internals(self) -> None:
        hidden_fields = {
            "hidden_dim",
            "image_patch_size",
            "positional_embedding_option",
            "stack_num_layers",
            "submodule_stack_hidden_dim",
            "ff_num_layers",
            "ff_stack_gate_flag",
            "attn_num_layers",
            "attn_stack_gate_flag",
            "top_k",
            "router_noisy_topk_flag",
        }
        public_fields = {
            "input_dim",
            "output_dim",
            "batch_size",
            "learning_rate",
            "num_epochs",
            "trainer_accelerator",
            "trainer_devices",
        }
        adaptive_fields = {"adaptive_generator_stack_hidden_dim", "weight_option"}

        for model_name in (
            "vit/linear",
            "vit/linear_adaptive",
            "vit/expert_linear",
            "vit/expert_linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                for field_key in public_fields:
                    self.assertIn(field_key, fields)
                for field_key in hidden_fields:
                    self.assertNotIn(field_key, fields)
                self.assertEqual(
                    adaptive_fields & fields.keys(),
                    adaptive_fields if model_name.endswith("_adaptive") else set(),
                )

    def test_mlp_mixer_schemas_expose_only_applicable_mixer_controls(self) -> None:
        common_fields = {
            "hidden_dim",
            "image_patch_size",
            "input_channels",
            "image_height",
            "stack_num_layers",
            "layer_norm_position",
            "token_mixer_stack_hidden_dim",
            "token_mixer_num_layers",
            "channel_mixer_stack_hidden_dim",
            "channel_mixer_num_layers",
            "stack_gate_flag",
            "stack_halting_flag",
            "memory_flag",
            "recurrent_flag",
        }
        excluded_fields = {
            "class_token_flag",
            "positional_embedding_option",
            "num_heads",
            "attn_num_heads",
            "query_dim",
            "key_dim",
            "value_dim",
            "causal_attention_mask_flag",
            "decoder_num_layers",
        }

        for backend in (
            "linear",
            "linear_adaptive",
            "expert_linear",
            "expert_linear_adaptive",
        ):
            model_name = f"mlp_mixer/{backend}"
            fields = _fields_by_key(config_schema(model_name))
            axes = _axes_by_key(search_space_schema(model_name, "baseline"))
            adaptive = "adaptive" in backend
            expert = "expert" in backend

            with self.subTest(model_name=model_name):
                self.assertGreaterEqual(set(fields), common_fields)
                self.assertFalse(set(fields) & excluded_fields)
                self.assertEqual(
                    "adaptive_generator_stack_hidden_dim" in fields,
                    adaptive,
                )
                self.assertEqual("top_k" in fields, expert)
                self.assertEqual("num_experts" in fields, expert)
                self.assertEqual("routing_initialization_mode" in fields, expert)
                self.assertEqual("compute_expert_mixture_flag" in fields, expert)
                self.assertGreaterEqual(
                    set(axes),
                    {
                        "learning_rate",
                        "hidden_dim",
                        "image_patch_size",
                        "stack_num_layers",
                        "token_mixer_stack_hidden_dim",
                        "channel_mixer_stack_hidden_dim",
                    },
                )
                self.assertEqual(
                    "adaptive_generator_stack_hidden_dim" in axes,
                    adaptive,
                )
                self.assertEqual("top_k" in axes, expert)
                self.assertEqual("num_experts" in axes, expert)

    def test_adaptive_expert_schemas_remove_attention_mode_switch(self) -> None:
        for model_name in (
            "bert/expert_linear_adaptive",
            "vit/expert_linear_adaptive",
        ):
            payload = config_schema(model_name)
            fields = _fields_by_key(payload)

            with self.subTest(model_name=model_name):
                self.assertNotIn("expert_attention_flag", fields)
                self.assertNotIn(
                    "EXPERT_ATTENTION_FLAG",
                    {field["configKey"] for field in payload["fields"]},
                )

    def test_grouped_bert_schemas_hide_builder_internals(self) -> None:
        common_public_fields = {
            "input_dim",
            "output_dim",
            "batch_size",
            "learning_rate",
            "num_epochs",
            "trainer_accelerator",
            "trainer_devices",
            "data_num_workers",
            "run_test_after_fit",
        }
        common_hidden_fields = {
            "hidden_dim",
            "token_type_vocab_size",
            "embedding_layer_norm_flag",
            "mlm_activation",
            "nsp_output_dim",
            "positional_embedding_option",
            "stack_num_layers",
            "submodule_stack_hidden_dim",
            "attn_num_layers",
            "attn_stack_gate_flag",
            "ff_num_layers",
            "ff_stack_gate_flag",
        }

        for model_name, additional_public_fields, additional_hidden_fields in (
            (
                "bert/linear_adaptive",
                {"adaptive_generator_stack_hidden_dim", "weight_option"},
                {"sequence_length"},
            ),
            ("bert/expert_linear", {"sequence_length"}, set()),
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                for field_key in common_public_fields | additional_public_fields:
                    self.assertIn(field_key, fields)
                for field_key in common_hidden_fields | additional_hidden_fields:
                    self.assertNotIn(field_key, fields)

    def test_config_schema_rejects_uppercase_config_import_aliases(self) -> None:
        with tempfile.TemporaryDirectory() as temp_dir:
            temp_path = Path(temp_dir)
            shared_module_name = "shared_config_alias_fixture"
            model_module_name = "model_config_alias_fixture"
            (temp_path / f"{shared_module_name}.py").write_text(
                "\n".join(["# Model", "HIDDEN_DIM: int = 128"]),
                encoding="utf-8",
            )
            (temp_path / f"{model_module_name}.py").write_text(
                "\n".join(
                    [
                        f"from {shared_module_name} import HIDDEN_DIM as WIDTH",
                        "",
                        "# Model",
                        "OUTPUT_DIM: int = 10",
                    ]
                ),
                encoding="utf-8",
            )
            sys.path.insert(0, temp_dir)
            try:
                importlib.invalidate_caches()
                config_module = importlib.import_module(model_module_name)
                with self.assertRaisesRegex(ValueError, "cannot use `as`"):
                    configuration_field_metadata(config_module)
            finally:
                sys.path.remove(temp_dir)
                sys.modules.pop(model_module_name, None)
                sys.modules.pop(shared_module_name, None)

    def test_config_schema_exposes_supported_field_types(self) -> None:
        linear_fields = _fields_by_key(config_schema("linears/linear"))
        self.assertEqual(linear_fields["hidden_dim"]["type"], "int")
        self.assertEqual(
            linear_fields["hidden_dim"]["default"],
            linear_config.HIDDEN_DIM,
        )
        self.assertEqual(linear_fields["layer_norm_position"]["type"], "enum")
        self.assertEqual(linear_fields["stack_bias_flag"]["type"], "bool")
        adaptive_fields = _fields_by_key(config_schema("linears/linear_adaptive"))
        self.assertEqual(adaptive_fields["stack_bias_flag"]["type"], "bool")
        self.assertEqual(
            adaptive_fields["stack_bias_flag"]["section"],
            "Layer Stack Options",
        )
        self.assertTrue(adaptive_fields["stack_bias_flag"]["default"])
        self.assertEqual(linear_fields["stack_num_layers"]["type"], "int")
        self.assertEqual(linear_fields["stack_num_layers"]["default"], 5)
        self.assertEqual(linear_fields["stack_num_layers"]["choices"], [])
        self.assertEqual(linear_fields["learning_rate"]["type"], "float")
        self.assertEqual(linear_fields["stack_gate_flag"]["type"], "bool")
        self.assertEqual(linear_fields["stack_activation"]["type"], "enum")
        self.assertIn("GELU", linear_fields["stack_activation"]["choices"])
        self.assertEqual(linear_fields["memory_flag"]["type"], "bool")
        self.assertEqual(linear_fields["gate_option"]["type"], "enum")
        self.assertEqual(linear_fields["gate_option"]["default"], "MULTIPLIER")
        self.assertTrue(linear_fields["gate_option"]["nullable"])
        self.assertIn("MULTIPLIER", linear_fields["gate_option"]["choices"])
        self.assertIn("ADDITION", linear_fields["gate_option"]["choices"])
        self.assertNotIn("INTERPOLATION", linear_fields["gate_option"]["choices"])
        self.assertNotIn("DISABLED", linear_fields["gate_option"]["choices"])
        self.assertEqual(linear_fields["gate_activation"]["type"], "enum")
        self.assertEqual(linear_fields["gate_activation"]["default"], "SIGMOID")
        self.assertTrue(linear_fields["gate_activation"]["nullable"])
        self.assertIn("TANH", linear_fields["gate_activation"]["choices"])
        self.assertEqual(linear_fields["gate_stack_independent_flag"]["type"], "bool")
        self.assertFalse(linear_fields["gate_stack_independent_flag"]["default"])
        self.assertEqual(linear_fields["gate_stack_hidden_dim"]["type"], "int")
        self.assertIsNone(linear_fields["gate_stack_hidden_dim"]["default"])
        self.assertTrue(linear_fields["gate_stack_hidden_dim"]["nullable"])
        self.assertEqual(linear_fields["gate_stack_bias_flag"]["type"], "bool")
        self.assertTrue(linear_fields["gate_stack_bias_flag"]["default"])
        self.assertTrue(linear_fields["gate_stack_bias_flag"]["nullable"])
        self.assertNotIn("gate_hidden_dim", linear_fields)
        self.assertNotIn("gate_layer_norm_position", linear_fields)
        self.assertNotIn("gate_bias_flag", linear_fields)
        self.assertEqual(
            linear_fields["gate_option"]["section"],
            "Gate Options",
        )
        self.assertEqual(
            linear_fields["gate_stack_hidden_dim"]["section"],
            "Gate Stack Options",
        )
        self.assertEqual(linear_fields["recurrent_gate_option"]["type"], "enum")
        self.assertEqual(
            linear_fields["recurrent_gate_option"]["default"],
            "MULTIPLIER",
        )
        self.assertTrue(linear_fields["recurrent_gate_option"]["nullable"])
        self.assertIn(
            "MULTIPLIER",
            linear_fields["recurrent_gate_option"]["choices"],
        )
        self.assertIn(
            "ADDITION",
            linear_fields["recurrent_gate_option"]["choices"],
        )
        self.assertNotIn(
            "INTERPOLATION",
            linear_fields["recurrent_gate_option"]["choices"],
        )
        self.assertNotIn(
            "DISABLED",
            linear_fields["recurrent_gate_option"]["choices"],
        )
        self.assertEqual(linear_fields["recurrent_gate_activation"]["type"], "enum")
        self.assertEqual(
            linear_fields["recurrent_gate_activation"]["default"],
            "SIGMOID",
        )
        self.assertTrue(linear_fields["recurrent_gate_activation"]["nullable"])
        self.assertIn(
            "TANH",
            linear_fields["recurrent_gate_activation"]["choices"],
        )
        self.assertEqual(
            linear_fields["recurrent_gate_stack_independent_flag"]["type"],
            "bool",
        )
        self.assertFalse(
            linear_fields["recurrent_gate_stack_independent_flag"]["default"],
        )
        self.assertEqual(
            linear_fields["recurrent_gate_stack_hidden_dim"]["type"],
            "int",
        )
        self.assertIsNone(linear_fields["recurrent_gate_stack_hidden_dim"]["default"])
        self.assertTrue(linear_fields["recurrent_gate_stack_hidden_dim"]["nullable"])
        self.assertEqual(
            linear_fields["recurrent_gate_stack_num_layers"]["type"],
            "int",
        )
        self.assertIsNone(
            linear_fields["recurrent_gate_stack_num_layers"]["default"],
        )
        self.assertTrue(
            linear_fields["recurrent_gate_stack_num_layers"]["nullable"],
        )
        self.assertEqual(
            linear_fields["recurrent_gate_stack_activation"]["type"],
            "enum",
        )
        self.assertIsNone(
            linear_fields["recurrent_gate_stack_activation"]["default"],
        )
        self.assertTrue(
            linear_fields["recurrent_gate_stack_activation"]["nullable"],
        )
        self.assertIn(
            "TANH",
            linear_fields["recurrent_gate_stack_activation"]["choices"],
        )
        self.assertNotIn("recurrent_gate_hidden_dim", linear_fields)
        self.assertNotIn("recurrent_gate_layer_norm_position", linear_fields)
        self.assertNotIn("recurrent_gate_bias_flag", linear_fields)
        self.assertEqual(
            linear_fields["recurrent_gate_option"]["section"],
            "Recurrent Gate Options",
        )
        self.assertEqual(
            linear_fields["recurrent_gate_stack_hidden_dim"]["section"],
            "Recurrent Gate Stack Options",
        )
        self.assertEqual(linear_fields["recurrent_layer_norm_position"]["type"], "enum")
        self.assertEqual(
            linear_fields["recurrent_layer_norm_position"]["default"],
            "DISABLED",
        )
        self.assertFalse(linear_fields["recurrent_layer_norm_position"]["nullable"])
        self.assertIn(
            "BEFORE",
            linear_fields["recurrent_layer_norm_position"]["choices"],
        )
        self.assertIn(
            "DEFAULT",
            linear_fields["recurrent_layer_norm_position"]["choices"],
        )
        self.assertIn(
            "AFTER",
            linear_fields["recurrent_layer_norm_position"]["choices"],
        )
        self.assertEqual(
            linear_fields["recurrent_layer_norm_position"]["section"],
            "Recurrent Layer Options",
        )
        self.assertEqual(linear_fields["memory_option"]["type"], "class")
        self.assertIn(
            "WeightedDynamicMemoryConfig",
            linear_fields["memory_option"]["choices"],
        )
        residual_selector = linear_fields["stack_residual_connection_option"]
        self.assertEqual(residual_selector["type"], "class")
        self.assertIsNone(residual_selector["default"])
        self.assertTrue(residual_selector["nullable"])
        self.assertEqual(
            residual_selector["choices"],
            [
                "AdditiveResidualConfig",
                "AttentionResidualConfig",
                "WeightedBlendResidualConfig",
                "WeightedResidualConfig",
            ],
        )
        self.assertEqual(linear_fields["memory_position_option"]["type"], "enum")
        self.assertEqual(
            linear_fields["memory_test_time_training_learning_rate"]["type"],
            "float",
        )
        self.assertEqual(
            linear_fields["memory_test_time_training_num_inner_steps"]["type"],
            "int",
        )
        self.assertEqual(
            linear_fields["hidden_dim"]["section"],
            "Global",
        )
        self.assertEqual(linear_fields["memory_flag"]["section"], "Memory Options")
        self.assertEqual(
            linear_fields["recurrent_flag"]["section"],
            "Recurrent Layer Options",
        )
        self.assertEqual(
            linear_fields["submodule_stack_hidden_dim"]["section"],
            "Layer Stack Submodule Options",
        )

        vit_fields = _fields_by_key(config_schema("vit/linear"))
        self.assertEqual(vit_fields["input_dim"]["type"], "int")
        self.assertNotIn("positional_embedding_option", vit_fields)
        self.assertNotIn("hidden_dim", vit_fields)

    def test_config_schema_exposes_field_descriptions(self) -> None:
        adaptive_fields = _fields_by_key(config_schema("linears/linear_adaptive"))

        self.assertTrue(
            all(field["description"].strip() for field in adaptive_fields.values())
        )
        self.assertIn(
            "optimizer steps",
            adaptive_fields["trainer_max_steps"]["description"],
        )
        self.assertIn(
            "validation data",
            adaptive_fields["trainer_limit_val_batches"]["description"],
        )
        self.assertIn(
            "model summary",
            adaptive_fields["trainer_enable_model_summary"]["description"],
        )
        self.assertIn(
            "profiling adds overhead",
            adaptive_fields["trainer_profiler"]["description"],
        )
        self.assertIn(
            "dedicated halting stack",
            adaptive_fields["halting_stack_bias_flag"]["description"],
        )
        self.assertIn(
            "applies activation, dropout",
            adaptive_fields["halting_stack_apply_output_postprocessing_flag"][
                "description"
            ],
        )
        self.assertIn(
            "smoke tests",
            adaptive_fields["run_test_after_fit"]["description"],
        )

    def test_config_schema_serializes_value_defaults(self) -> None:
        linear_fields = _fields_by_key(config_schema("linears/linear"))
        adaptive_fields = _fields_by_key(config_schema("linears/linear_adaptive"))

        self.assertEqual(
            linear_fields["hidden_dim"]["default"],
            linear_config.HIDDEN_DIM,
        )
        self.assertEqual(linear_fields["stack_activation"]["default"], "GELU")
        vit_fields = _fields_by_key(config_schema("vit/linear"))
        self.assertEqual(vit_fields["input_dim"]["default"], 224 * 224 * 3)
        self.assertNotIn("positional_embedding_option", vit_fields)
        self.assertFalse(
            any(key.endswith("_layer_adaptive_flag") for key in adaptive_fields)
        )

    def test_transformer_schemas_expose_feed_forward_controller_sections(self) -> None:
        expected_sections = {
            "ff_num_layers": "Feed-Forward Stack Options",
            "ff_bias_flag": "Feed-Forward Stack Options",
            "ff_stack_hidden_dim": "Feed-Forward Stack Options",
            "ff_stack_activation": "Feed-Forward Stack Options",
            "ff_stack_gate_flag": "Feed-Forward Gate Options",
            "ff_gate_stack_hidden_dim": "Feed-Forward Gate Stack Options",
            "ff_stack_halting_flag": "Feed-Forward Halting Options",
            "ff_halting_stack_hidden_dim": "Feed-Forward Halting Stack Options",
            "ff_memory_flag": "Feed-Forward Memory Options",
            "ff_memory_stack_hidden_dim": "Feed-Forward Memory Stack Options",
            "ff_recurrent_flag": "Feed-Forward Recurrent Layer Options",
            "ff_recurrent_stack_gate_flag": "Feed-Forward Recurrent Gate Options",
            "ff_recurrent_gate_stack_hidden_dim": (
                "Feed-Forward Recurrent Gate Stack Options"
            ),
            "ff_recurrent_stack_halting_flag": (
                "Feed-Forward Recurrent Halting Options"
            ),
            "ff_recurrent_halting_stack_hidden_dim": (
                "Feed-Forward Recurrent Halting Stack Options"
            ),
        }

        for model_name in (
            "bert/linear",
            "bert/expert_linear_adaptive",
            "transformer/linear",
            "transformer/linear_adaptive",
            "transformer/expert_linear",
            "transformer/expert_linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                for field_key, section in expected_sections.items():
                    self.assertIn(field_key, fields)
                    self.assertEqual(fields[field_key]["section"], section)
                self.assertNotIn("ff_stack_num_layers", fields)
                self.assertNotIn("ff_stack_bias_flag", fields)
                self.assertEqual(
                    fields["ff_stack_gate_flag"]["flag"],
                    "--ff-stack-gate-flag",
                )
                self.assertFalse(fields["ff_stack_gate_flag"]["default"])
                self.assertFalse(fields["ff_memory_flag"]["default"])
                self.assertFalse(fields["ff_recurrent_flag"]["default"])
                self.assertFalse(fields["ff_gate_stack_independent_flag"]["default"])
                self.assertIsNone(fields["ff_gate_stack_hidden_dim"]["default"])
                self.assertTrue(fields["ff_gate_stack_hidden_dim"]["nullable"])
                self.assertIn(
                    "feed-forward gate",
                    fields["ff_gate_option"]["description"],
                )

        for model_name in (
            "bert/linear_adaptive",
            "bert/expert_linear",
            "vit/linear",
            "vit/linear_adaptive",
            "vit/expert_linear",
            "vit/expert_linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                visible_fields = (
                    {"ff_bias_flag"} if model_name.endswith("_adaptive") else set()
                )
                self.assertEqual(
                    expected_sections.keys() & fields.keys(), visible_fields
                )
                for field_key in visible_fields:
                    self.assertEqual(
                        fields[field_key]["section"], expected_sections[field_key]
                    )

    def test_transformer_schemas_expose_attention_projection_controller_sections(
        self,
    ) -> None:
        expected_sections = {
            "attn_num_layers": "Attention Projection Stack Options",
            "attn_bias_flag": "Attention Projection Stack Options",
            "attn_stack_hidden_dim": "Attention Projection Stack Options",
            "attn_stack_activation": "Attention Projection Stack Options",
            "attn_stack_gate_flag": "Attention Projection Gate Options",
            "attn_gate_stack_hidden_dim": ("Attention Projection Gate Stack Options"),
            "attn_stack_halting_flag": "Attention Projection Halting Options",
            "attn_halting_stack_hidden_dim": (
                "Attention Projection Halting Stack Options"
            ),
            "attn_memory_flag": "Attention Projection Memory Options",
            "attn_memory_stack_hidden_dim": (
                "Attention Projection Memory Stack Options"
            ),
            "attn_recurrent_flag": ("Attention Projection Recurrent Layer Options"),
            "attn_recurrent_stack_gate_flag": (
                "Attention Projection Recurrent Gate Options"
            ),
            "attn_recurrent_gate_stack_hidden_dim": (
                "Attention Projection Recurrent Gate Stack Options"
            ),
            "attn_recurrent_stack_halting_flag": (
                "Attention Projection Recurrent Halting Options"
            ),
            "attn_recurrent_halting_stack_hidden_dim": (
                "Attention Projection Recurrent Halting Stack Options"
            ),
        }

        for model_name in (
            "bert/linear",
            "bert/expert_linear_adaptive",
            "transformer/linear",
            "transformer/linear_adaptive",
            "transformer/expert_linear",
            "transformer/expert_linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                for field_key, section in expected_sections.items():
                    self.assertIn(field_key, fields)
                    self.assertEqual(fields[field_key]["section"], section)
                self.assertNotIn("attn_stack_num_layers", fields)
                self.assertNotIn("attn_stack_bias_flag", fields)
                self.assertEqual(
                    fields["attn_stack_gate_flag"]["flag"],
                    "--attn-stack-gate-flag",
                )
                self.assertFalse(fields["attn_stack_gate_flag"]["default"])
                self.assertFalse(fields["attn_memory_flag"]["default"])
                self.assertFalse(fields["attn_recurrent_flag"]["default"])
                self.assertFalse(fields["attn_gate_stack_independent_flag"]["default"])
                self.assertIsNone(fields["attn_gate_stack_hidden_dim"]["default"])
                self.assertTrue(fields["attn_gate_stack_hidden_dim"]["nullable"])
                self.assertIn(
                    "attention projection gate",
                    fields["attn_gate_option"]["description"],
                )

        for model_name in (
            "bert/linear_adaptive",
            "bert/expert_linear",
            "vit/linear",
            "vit/linear_adaptive",
            "vit/expert_linear",
            "vit/expert_linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                visible_fields = (
                    {"attn_bias_flag"} if model_name.endswith("_adaptive") else set()
                )
                self.assertEqual(
                    expected_sections.keys() & fields.keys(), visible_fields
                )
                for field_key in visible_fields:
                    self.assertEqual(
                        fields[field_key]["section"], expected_sections[field_key]
                    )

    def test_transformer_schemas_and_search_axes_cover_translation_backends(
        self,
    ) -> None:
        for backend in (
            "linear",
            "linear_adaptive",
            "expert_linear",
            "expert_linear_adaptive",
        ):
            model_name = f"transformer/{backend}"
            with self.subTest(model_name=model_name):
                fields = _fields_by_key(config_schema(model_name))
                self.assertTrue(
                    {
                        "vocab_size",
                        "model_dim",
                        "source_sequence_length",
                        "target_sequence_length",
                        "encoder_num_layers",
                        "decoder_num_layers",
                    }.issubset(fields)
                )
                axes = _axes_by_key(search_space_schema(model_name, "baseline"))
                self.assertTrue(
                    {
                        "learning_rate",
                        "model_dim",
                        "encoder_num_layers",
                        "decoder_num_layers",
                        "attn_num_heads",
                        "ff_stack_hidden_dim",
                    }.issubset(axes)
                )
                if "expert" in backend:
                    self.assertTrue({"num_experts", "top_k"}.issubset(axes))
                if "adaptive" in backend:
                    roles = (
                        (
                            "attention_projection_adaptive",
                            "attention_expert_adaptive",
                            "router_adaptive",
                            "feed_forward_adaptive",
                        )
                        if "expert" in backend
                        else (
                            "projection_adaptive",
                            "feed_forward_adaptive",
                        )
                    )
                    adaptive_axes = {
                        f"{role}_{field}"
                        for role in roles
                        for field in (
                            "weight_option",
                            "bias_option",
                            "diagonal_option",
                            "row_mask_option",
                        )
                    }
                    self.assertTrue(adaptive_axes.issubset(axes))
                    self.assertFalse(
                        {
                            "weight_option",
                            "bias_option",
                            "diagonal_option",
                            "row_mask_option",
                        }
                        & set(axes)
                    )

    def test_linear_schemas_do_not_expose_halting_output_dims(self) -> None:
        removed_field_keys = {
            "halting_output_dim",
            "recurrent_halting_output_dim",
        }
        removed_config_keys = {
            "HALTING_OUTPUT_DIM",
            "RECURRENT_HALTING_OUTPUT_DIM",
        }

        for model_name in ("linears/linear", "linears/linear_adaptive"):
            payload = config_schema(model_name)
            fields = _fields_by_key(payload)
            config_keys = {field["configKey"] for field in payload["fields"]}

            with self.subTest(model_name=model_name):
                for field_key in removed_field_keys:
                    self.assertNotIn(field_key, fields)
                for config_key in removed_config_keys:
                    self.assertNotIn(config_key, config_keys)

    def test_linear_adaptive_schema_uses_controller_stack_field_names(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear_adaptive"))
        expected_stack_fields = {
            "gate_stack_hidden_dim",
            "gate_stack_layer_norm_position",
            "gate_stack_bias_flag",
            "halting_stack_hidden_dim",
            "halting_stack_layer_norm_position",
            "halting_stack_bias_flag",
            "memory_stack_hidden_dim",
            "memory_stack_layer_norm_position",
            "memory_stack_bias_flag",
            "recurrent_gate_stack_hidden_dim",
            "recurrent_gate_stack_layer_norm_position",
            "recurrent_gate_stack_bias_flag",
            "recurrent_halting_stack_hidden_dim",
            "recurrent_halting_stack_layer_norm_position",
            "recurrent_halting_stack_bias_flag",
        }
        legacy_fields = {name.replace("_stack_", "_") for name in expected_stack_fields}

        for field_name in expected_stack_fields:
            with self.subTest(field_name=field_name):
                self.assertIn(field_name, fields)

        for field_name in legacy_fields:
            with self.subTest(field_name=field_name):
                self.assertNotIn(field_name, fields)

    def test_model_schemas_use_controller_stack_field_names(self) -> None:
        experts_controller_stack_fields = {
            "gate_stack_independent_flag",
            "gate_stack_hidden_dim",
            "gate_stack_layer_norm_position",
            "gate_stack_bias_flag",
            "halting_stack_independent_flag",
            "halting_stack_hidden_dim",
            "halting_stack_layer_norm_position",
            "halting_stack_bias_flag",
            "memory_stack_independent_flag",
            "memory_stack_hidden_dim",
            "memory_stack_layer_norm_position",
            "memory_stack_bias_flag",
            "recurrent_gate_stack_independent_flag",
            "recurrent_gate_stack_hidden_dim",
            "recurrent_gate_stack_layer_norm_position",
            "recurrent_gate_stack_bias_flag",
            "recurrent_halting_stack_independent_flag",
            "recurrent_halting_stack_hidden_dim",
            "recurrent_halting_stack_layer_norm_position",
            "recurrent_halting_stack_bias_flag",
            "router_stack_hidden_dim",
            "router_stack_layer_norm_position",
            "expert_gate_stack_independent_flag",
            "expert_gate_stack_hidden_dim",
            "expert_gate_stack_layer_norm_position",
            "expert_gate_stack_bias_flag",
            "expert_halting_stack_independent_flag",
            "expert_halting_stack_hidden_dim",
            "expert_halting_stack_layer_norm_position",
            "expert_halting_stack_bias_flag",
            "expert_memory_stack_independent_flag",
            "expert_memory_stack_hidden_dim",
            "expert_memory_stack_layer_norm_position",
            "expert_memory_stack_bias_flag",
            "expert_recurrent_gate_stack_independent_flag",
            "expert_recurrent_gate_stack_hidden_dim",
            "expert_recurrent_gate_stack_layer_norm_position",
            "expert_recurrent_gate_stack_bias_flag",
            "expert_recurrent_halting_stack_independent_flag",
            "expert_recurrent_halting_stack_hidden_dim",
            "expert_recurrent_halting_stack_layer_norm_position",
            "expert_recurrent_halting_stack_bias_flag",
        }
        expected_by_model = {
            "experts/linear": experts_controller_stack_fields,
            "experts/linear_adaptive": experts_controller_stack_fields,
            "neuron/linear": {
                "gate_stack_hidden_dim",
                "gate_stack_layer_norm_position",
                "gate_stack_bias_flag",
                "halting_stack_hidden_dim",
                "halting_stack_layer_norm_position",
                "halting_stack_bias_flag",
                "cluster_halting_stack_hidden_dim",
                "cluster_halting_stack_layer_norm_position",
                "cluster_halting_stack_bias_flag",
            },
            "neuron/linear_adaptive": {
                "gate_stack_hidden_dim",
                "gate_stack_layer_norm_position",
                "gate_stack_bias_flag",
                "halting_stack_hidden_dim",
                "halting_stack_layer_norm_position",
                "halting_stack_bias_flag",
                "memory_stack_hidden_dim",
                "memory_stack_layer_norm_position",
                "memory_stack_bias_flag",
                "recurrent_gate_stack_hidden_dim",
                "recurrent_gate_stack_layer_norm_position",
                "recurrent_gate_stack_bias_flag",
                "recurrent_halting_stack_hidden_dim",
                "recurrent_halting_stack_layer_norm_position",
                "recurrent_halting_stack_bias_flag",
                "cluster_halting_stack_hidden_dim",
                "cluster_halting_stack_layer_norm_position",
                "cluster_halting_stack_bias_flag",
            },
            "neuron/expert_linear": {
                *experts_controller_stack_fields,
                "cluster_halting_stack_hidden_dim",
                "cluster_halting_stack_layer_norm_position",
                "cluster_halting_stack_bias_flag",
            },
            "neuron/expert_linear_adaptive": {
                *experts_controller_stack_fields,
                "cluster_halting_stack_hidden_dim",
                "cluster_halting_stack_layer_norm_position",
                "cluster_halting_stack_bias_flag",
            },
        }

        for model_name, expected_stack_fields in expected_by_model.items():
            fields = _fields_by_key(config_schema(model_name))
            legacy_fields = {
                field_name.replace("_stack_", "_")
                for field_name in expected_stack_fields
            }
            with self.subTest(model_name=model_name):
                for field_name in expected_stack_fields:
                    self.assertIn(field_name, fields)
                for field_name in legacy_fields:
                    self.assertNotIn(field_name, fields)
                if model_name.startswith("experts/"):
                    self.assertEqual(
                        fields["memory_flag"]["section"],
                        "Memory Options",
                    )
                    self.assertEqual(
                        fields["memory_stack_hidden_dim"]["section"],
                        "Memory Stack Options",
                    )
                    self.assertEqual(
                        fields["recurrent_halting_threshold"]["section"],
                        "Recurrent Halting Options",
                    )
                    self.assertEqual(
                        fields["recurrent_halting_stack_hidden_dim"]["section"],
                        "Recurrent Halting Stack Options",
                    )
                    self.assertIsNone(fields["memory_stack_hidden_dim"]["default"])
                    self.assertTrue(fields["memory_stack_hidden_dim"]["nullable"])
                    self.assertFalse(fields["memory_stack_independent_flag"]["default"])
                    self.assertFalse(
                        fields["recurrent_halting_stack_independent_flag"]["default"]
                    )

    def test_experts_schemas_use_sampler_router_section_labels(self) -> None:
        for model_name in (
            "experts/linear",
            "experts/linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                self.assertEqual(
                    fields["sampler_threshold"]["section"],
                    "Sampler Model Options",
                )
                self.assertEqual(
                    fields["sampler_switch_loss_weight"]["section"],
                    "Sampler Model Options",
                )
                self.assertEqual(
                    fields["router_noisy_topk_flag"]["section"],
                    "Router Options",
                )
                self.assertEqual(
                    fields["router_stack_hidden_dim"]["section"],
                    "Router Stack Options",
                )
                self.assertEqual(fields["router_stack_hidden_dim"]["default"], 32)
                self.assertFalse(fields["router_stack_hidden_dim"]["nullable"])
                self.assertEqual(
                    fields["router_stack_num_layers"]["default"],
                    2,
                )
                self.assertFalse(fields["router_stack_num_layers"]["nullable"])
                self.assertEqual(
                    fields["router_bias_flag"]["section"],
                    "Router Stack Options",
                )
                self.assertTrue(fields["router_bias_flag"]["default"])
                self.assertFalse(fields["router_bias_flag"]["nullable"])
                self.assertNotIn("router_stack_independent_flag", fields)
                self.assertNotIn("sampler_stack_independent_flag", fields)
                self.assertNotIn("sampler_stack_hidden_dim", fields)
                self.assertNotIn("sampler_bias_flag", fields)

    def test_experts_linear_adaptive_schema_exposes_router_controller_sections(
        self,
    ) -> None:
        fields = _fields_by_key(config_schema("experts/linear_adaptive"))
        expected_sections = {
            "router_stack_gate_flag": "Router Gate Options",
            "router_gate_stack_hidden_dim": "Router Gate Stack Options",
            "router_stack_halting_flag": "Router Halting Options",
            "router_halting_stack_hidden_dim": "Router Halting Stack Options",
            "router_memory_flag": "Router Memory Options",
            "router_memory_stack_hidden_dim": "Router Memory Stack Options",
            "router_recurrent_flag": "Router Recurrent Layer Options",
            "router_recurrent_stack_gate_flag": "Router Recurrent Gate Options",
            "router_recurrent_gate_stack_hidden_dim": (
                "Router Recurrent Gate Stack Options"
            ),
            "router_recurrent_stack_halting_flag": "Router Recurrent Halting Options",
            "router_recurrent_halting_stack_hidden_dim": (
                "Router Recurrent Halting Stack Options"
            ),
        }

        for field_key, section in expected_sections.items():
            with self.subTest(field_key=field_key):
                self.assertIn(field_key, fields)
                self.assertEqual(fields[field_key]["section"], section)

        self.assertFalse(fields["router_stack_gate_flag"]["default"])
        self.assertFalse(fields["router_memory_flag"]["default"])
        self.assertFalse(fields["router_recurrent_flag"]["default"])
        self.assertFalse(fields["router_gate_stack_independent_flag"]["default"])
        self.assertIsNone(fields["router_gate_stack_hidden_dim"]["default"])
        self.assertTrue(fields["router_gate_stack_hidden_dim"]["nullable"])
        self.assertEqual(
            fields["router_stack_gate_flag"]["flag"],
            "--router-stack-gate-flag",
        )
        self.assertEqual(
            fields["router_memory_flag"]["flag"],
            "--router-memory-flag",
        )
        self.assertEqual(
            fields["router_recurrent_flag"]["flag"],
            "--router-recurrent-flag",
        )

    def test_experts_schemas_use_mixture_and_expert_stack_section_labels(self) -> None:
        expected = {
            "top_k": {
                "section": "Mixture Of Experts Model Options",
                "type": "int",
                "default": 3,
                "nullable": False,
            },
            "num_experts": {
                "section": "Mixture Of Experts Model Options",
                "type": "int",
                "default": 12,
                "nullable": False,
            },
            "capacity_factor": {
                "section": "Mixture Of Experts Model Options",
                "type": "float",
                "default": 0.0,
                "nullable": False,
            },
            "dropped_token_behavior": {
                "section": "Mixture Of Experts Model Options",
                "type": "enum",
                "default": "ZEROS",
                "nullable": False,
            },
            "compute_expert_mixture_flag": {
                "section": "Mixture Of Experts Model Options",
                "type": "bool",
                "default": True,
                "nullable": False,
            },
            "weighted_parameters_flag": {
                "section": "Mixture Of Experts Model Options",
                "type": "bool",
                "default": True,
                "nullable": False,
            },
            "weighting_position_option": {
                "section": "Mixture Of Experts Model Options",
                "type": "enum",
                "default": "AFTER_EXPERTS",
                "nullable": False,
            },
            "routing_initialization_mode": {
                "section": "Mixture Of Experts Model Options",
                "type": "enum",
                "default": "LAYER",
                "nullable": False,
            },
            "expert_stack_hidden_dim": {
                "section": "Expert Stack Options",
                "type": "int",
                "default": 32,
                "nullable": False,
            },
            "expert_stack_num_layers": {
                "section": "Expert Stack Options",
                "type": "int",
                "default": 2,
                "nullable": False,
            },
            "expert_bias_flag": {
                "section": "Expert Stack Options",
                "type": "bool",
                "default": True,
                "nullable": False,
            },
        }

        for model_name in (
            "experts/linear",
            "experts/linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                for field_key, expected_values in expected.items():
                    field = fields[field_key]
                    self.assertEqual(field["key"], field["configKey"])
                    self.assertEqual(
                        field["flag"],
                        f"--{field_key.replace('_', '-')}",
                    )
                    for property_name, expected_value in expected_values.items():
                        with self.subTest(
                            model_name=model_name,
                            field_key=field_key,
                            property_name=property_name,
                        ):
                            self.assertEqual(field[property_name], expected_value)

    def test_experts_schemas_expose_expert_internal_controller_sections(self) -> None:
        expected = {
            "expert_stack_gate_flag": {
                "section": "Expert Gate Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_gate_option": {
                "section": "Expert Gate Options",
                "type": "enum",
                "default": "MULTIPLIER",
                "nullable": True,
            },
            "expert_gate_stack_independent_flag": {
                "section": "Expert Gate Stack Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_gate_stack_hidden_dim": {
                "section": "Expert Gate Stack Options",
                "type": "int",
                "default": None,
                "nullable": True,
            },
            "expert_stack_halting_flag": {
                "section": "Expert Halting Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_halting_threshold": {
                "section": "Expert Halting Options",
                "type": "float",
                "default": 0.999,
                "nullable": False,
            },
            "expert_halting_stack_hidden_dim": {
                "section": "Expert Halting Stack Options",
                "type": "int",
                "default": None,
                "nullable": True,
            },
            "expert_memory_flag": {
                "section": "Expert Memory Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_memory_option": {
                "section": "Expert Memory Options",
                "type": "class",
                "default": "GatedResidualDynamicMemoryConfig",
                "nullable": False,
            },
            "expert_memory_stack_hidden_dim": {
                "section": "Expert Memory Stack Options",
                "type": "int",
                "default": None,
                "nullable": True,
            },
            "expert_recurrent_flag": {
                "section": "Expert Recurrent Layer Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_recurrent_layer_norm_position": {
                "section": "Expert Recurrent Layer Options",
                "type": "enum",
                "default": "DISABLED",
                "nullable": False,
            },
            "expert_recurrent_stack_gate_flag": {
                "section": "Expert Recurrent Gate Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_recurrent_gate_stack_hidden_dim": {
                "section": "Expert Recurrent Gate Stack Options",
                "type": "int",
                "default": None,
                "nullable": True,
            },
            "expert_recurrent_stack_halting_flag": {
                "section": "Expert Recurrent Halting Options",
                "type": "bool",
                "default": False,
                "nullable": False,
            },
            "expert_recurrent_halting_stack_hidden_dim": {
                "section": "Expert Recurrent Halting Stack Options",
                "type": "int",
                "default": None,
                "nullable": True,
            },
        }

        for model_name in (
            "experts/linear",
            "experts/linear_adaptive",
        ):
            fields = _fields_by_key(config_schema(model_name))

            with self.subTest(model_name=model_name):
                for field_key, expected_values in expected.items():
                    field = fields[field_key]
                    self.assertEqual(
                        field["flag"],
                        f"--{field_key.replace('_', '-')}",
                    )
                    for property_name, expected_value in expected_values.items():
                        with self.subTest(
                            model_name=model_name,
                            field_key=field_key,
                            property_name=property_name,
                        ):
                            self.assertEqual(field[property_name], expected_value)
                self.assertIn(
                    "MULTIPLIER",
                    fields["expert_recurrent_gate_option"]["choices"],
                )
                self.assertIn(
                    "GatedResidualDynamicMemoryConfig",
                    fields["expert_memory_option"]["choices"],
                )

    def test_config_schema_excludes_abstract_class_choices(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear_adaptive"))

        self.assertNotIn("DynamicWeightConfig", fields["weight_option"]["choices"])
        self.assertIn(
            "SingleModelDynamicWeightConfig",
            fields["weight_option"]["choices"],
        )
        self.assertNotIn("DynamicBiasConfig", fields["bias_option"]["choices"])
        self.assertIn(
            "AdditiveDynamicBiasConfig",
            fields["bias_option"]["choices"],
        )
        self.assertNotIn("DynamicDiagonalConfig", fields["diagonal_option"]["choices"])
        self.assertIn(
            "StandardDynamicDiagonalConfig",
            fields["diagonal_option"]["choices"],
        )
        self.assertNotIn("AxisMaskConfig", fields["row_mask_option"]["choices"])
        self.assertIn(
            "DiagonalAxisMaskConfig",
            fields["row_mask_option"]["choices"],
        )

    def test_config_schema_orders_adaptive_class_choices_from_search_space(
        self,
    ) -> None:
        fields = _fields_by_key(config_schema("linears/linear_adaptive", "baseline"))

        self.assertEqual(
            fields["weight_option"]["choices"][0],
            "SingleModelDynamicWeightConfig",
        )
        self.assertEqual(
            fields["bias_option"]["choices"][0],
            "AffineTransformDynamicBiasConfig",
        )
        self.assertEqual(
            fields["diagonal_option"]["choices"][0],
            "StandardDynamicDiagonalConfig",
        )
        self.assertEqual(
            fields["row_mask_option"]["choices"][0],
            "DiagonalAxisMaskConfig",
        )

    def test_config_schema_exposes_adaptive_component_option_flags(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear_adaptive"))

        expected_flags = {
            "weight_option_flag": "Weight Generator Options",
            "bias_option_flag": "Bias Generator Options",
            "diagonal_option_flag": "Diagonal Generator Options",
            "mask_option_flag": "Mask Options",
        }
        for field_key, section in expected_flags.items():
            with self.subTest(field_key=field_key):
                self.assertEqual(fields[field_key]["type"], "bool")
                self.assertFalse(fields[field_key]["default"])
                self.assertEqual(fields[field_key]["choices"], [True, False])
                self.assertEqual(fields[field_key]["section"], section)

        self.assertEqual(
            fields["adaptive_generator_stack_hidden_dim"]["section"],
            "Adaptive Generator Stack Options",
        )
        self.assertEqual(
            fields["adaptive_generator_stack_num_layers"]["section"],
            "Adaptive Generator Stack Options",
        )
        self.assertNotEqual(
            fields["adaptive_generator_stack_hidden_dim"]["section"],
            "Mask Options",
        )

        self.assertEqual(fields["weight_option"]["type"], "class")
        self.assertIn(
            "SingleModelDynamicWeightConfig",
            fields["weight_option"]["choices"],
        )
        self.assertEqual(fields["bias_option"]["type"], "class")
        self.assertIn(
            "AdditiveDynamicBiasConfig",
            fields["bias_option"]["choices"],
        )
        self.assertEqual(fields["diagonal_option"]["type"], "class")
        self.assertIn(
            "StandardDynamicDiagonalConfig",
            fields["diagonal_option"]["choices"],
        )
        self.assertEqual(fields["row_mask_option"]["type"], "class")
        self.assertEqual(fields["row_mask_option"]["section"], "Mask Options")
        self.assertIn(
            "WeightInformedScoreAxisMaskConfig",
            fields["row_mask_option"]["choices"],
        )
        self.assertEqual(
            fields["weight_generator_stack_independent_flag"]["section"],
            "Weight Generator Stack Options",
        )
        self.assertEqual(
            fields["bias_generator_stack_independent_flag"]["section"],
            "Bias Generator Stack Options",
        )
        self.assertEqual(
            fields["diagonal_generator_stack_independent_flag"]["section"],
            "Diagonal Generator Stack Options",
        )
        self.assertEqual(
            fields["mask_generator_stack_independent_flag"]["section"],
            "Mask Stack Options",
        )
        self.assertEqual(
            fields["mask_generator_stack_hidden_dim"]["section"],
            "Mask Stack Options",
        )

    def test_config_schema_exposes_boundary_model_adaptive_options(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear_adaptive"))

        self.assertNotIn("input_layer_model_option", fields)
        self.assertNotIn("output_layer_model_option", fields)
        self.assertFalse(any(key.endswith("_layer_adaptive_flag") for key in fields))
        expected_options = {
            "input_layer_weight_option": "Input Boundary Model Options",
            "input_layer_bias_option": "Input Boundary Model Options",
            "input_layer_diagonal_option": "Input Boundary Model Options",
            "input_layer_row_mask_option": "Input Boundary Model Options",
            "output_layer_weight_option": "Output Boundary Model Options",
            "output_layer_bias_option": "Output Boundary Model Options",
            "output_layer_diagonal_option": "Output Boundary Model Options",
            "output_layer_row_mask_option": "Output Boundary Model Options",
        }
        for field_key, section in expected_options.items():
            with self.subTest(field_key=field_key):
                self.assertEqual(fields[field_key]["section"], section)
                self.assertEqual(fields[field_key]["type"], "class")
                self.assertIsNone(fields[field_key]["default"])
                self.assertTrue(fields[field_key]["nullable"])
                self.assertNotIn("searchChoices", fields[field_key])

    def test_linear_adaptive_schema_exposes_full_adaptive_surface(self) -> None:
        fields = _fields_by_key(config_schema("experts/linear_adaptive"))
        linear_fields = _fields_by_key(config_schema("linears/linear_adaptive"))

        linear_parity_keys = [
            "weight_option_flag",
            "weight_option",
            "weight_generator_stack_independent_flag",
            "weight_generator_stack_hidden_dim",
            "bias_option_flag",
            "bias_option",
            "bias_generator_stack_independent_flag",
            "diagonal_option_flag",
            "diagonal_option",
            "diagonal_generator_stack_independent_flag",
            "mask_option_flag",
            "row_mask_option",
            "mask_generator_stack_independent_flag",
            "input_layer_weight_option",
            "input_layer_bias_option",
            "input_layer_diagonal_option",
            "input_layer_row_mask_option",
            "output_layer_weight_option",
            "output_layer_bias_option",
            "output_layer_diagonal_option",
            "output_layer_row_mask_option",
            "adaptive_generator_stack_hidden_dim",
        ]
        for field_key in linear_parity_keys:
            with self.subTest(field_key=field_key):
                self.assertIn(field_key, fields)
                self.assertEqual(
                    fields[field_key]["type"], linear_fields[field_key]["type"]
                )
                self.assertEqual(
                    fields[field_key]["nullable"],
                    linear_fields[field_key]["nullable"],
                )
                self.assertEqual(
                    fields[field_key]["choices"],
                    linear_fields[field_key]["choices"],
                )

        expected_router_pairs = {
            "router_weight_option_flag": "weight_option_flag",
            "router_weight_option": "weight_option",
            "router_weight_generator_stack_independent_flag": (
                "weight_generator_stack_independent_flag"
            ),
            "router_weight_generator_stack_hidden_dim": (
                "weight_generator_stack_hidden_dim"
            ),
            "router_bias_option_flag": "bias_option_flag",
            "router_bias_option": "bias_option",
            "router_bias_generator_stack_independent_flag": (
                "bias_generator_stack_independent_flag"
            ),
            "router_diagonal_option_flag": "diagonal_option_flag",
            "router_diagonal_option": "diagonal_option",
            "router_diagonal_generator_stack_independent_flag": (
                "diagonal_generator_stack_independent_flag"
            ),
            "router_mask_option_flag": "mask_option_flag",
            "router_row_mask_option": "row_mask_option",
            "router_mask_generator_stack_independent_flag": (
                "mask_generator_stack_independent_flag"
            ),
        }
        for router_key, linear_key in expected_router_pairs.items():
            with self.subTest(router_key=router_key):
                self.assertIn(router_key, fields)
                self.assertEqual(
                    fields[router_key]["type"], linear_fields[linear_key]["type"]
                )
                self.assertEqual(
                    fields[router_key]["nullable"],
                    linear_fields[linear_key]["nullable"],
                )
                self.assertEqual(
                    fields[router_key]["choices"],
                    linear_fields[linear_key]["choices"],
                )

        self.assertEqual(
            fields["router_weight_option_flag"]["section"],
            "Router Weight Generator Options",
        )
        self.assertEqual(
            fields["router_weight_generator_stack_hidden_dim"]["section"],
            "Router Weight Generator Stack Options",
        )
        self.assertEqual(
            fields["router_mask_generator_stack_hidden_dim"]["section"],
            "Router Mask Stack Options",
        )

    def test_linear_adaptive_schema_locks_router_adaptive_preset_flags(
        self,
    ) -> None:
        fields = _fields_by_key(
            config_schema("experts/linear_adaptive", "adaptive-bank-router")
        )

        self.assertTrue(fields["router_weight_option_flag"]["locked"])
        self.assertEqual(fields["router_weight_option_flag"]["lockedValue"], True)
        self.assertTrue(fields["router_weight_option"]["locked"])
        self.assertEqual(
            fields["router_weight_option"]["lockedValue"],
            "LayeredWeightedBankDynamicWeightConfig",
        )

    def test_config_schema_exposes_nullable_controller_stack_overrides(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear"))

        self.assertEqual(
            fields["submodule_stack_hidden_dim"]["section"],
            "Layer Stack Submodule Options",
        )
        self.assertEqual(fields["submodule_stack_hidden_dim"]["type"], "int")
        self.assertFalse(fields["submodule_stack_hidden_dim"]["nullable"])

        self.assertEqual(fields["memory_stack_independent_flag"]["type"], "bool")
        self.assertFalse(fields["memory_stack_independent_flag"]["default"])
        self.assertEqual(fields["memory_stack_hidden_dim"]["type"], "int")
        self.assertIsNone(fields["memory_stack_hidden_dim"]["default"])
        self.assertTrue(fields["memory_stack_hidden_dim"]["nullable"])
        self.assertEqual(fields["memory_stack_hidden_dim"]["choices"], [])
        self.assertNotIn("memory_hidden_dim", fields)
        self.assertNotIn("memory_layer_norm_position", fields)
        self.assertNotIn("memory_bias_flag", fields)
        self.assertEqual(fields["memory_stack_dropout_probability"]["type"], "float")
        self.assertIsNone(fields["memory_stack_dropout_probability"]["default"])
        self.assertTrue(fields["memory_stack_dropout_probability"]["nullable"])
        self.assertEqual(fields["memory_stack_activation"]["type"], "enum")
        self.assertIsNone(fields["memory_stack_activation"]["default"])
        self.assertTrue(fields["memory_stack_activation"]["nullable"])
        self.assertIn("GELU", fields["memory_stack_activation"]["choices"])
        self.assertEqual(
            fields["memory_stack_apply_output_postprocessing_flag"]["type"],
            "bool",
        )
        self.assertIsNone(
            fields["memory_stack_apply_output_postprocessing_flag"]["default"]
        )
        self.assertTrue(
            fields["memory_stack_apply_output_postprocessing_flag"]["nullable"]
        )
        self.assertEqual(
            fields["memory_stack_apply_output_postprocessing_flag"]["choices"],
            [True, False],
        )
        self.assertEqual(fields["gate_stack_activation"]["type"], "enum")
        self.assertEqual(fields["gate_stack_activation"]["default"], "TANH")
        self.assertTrue(fields["gate_stack_activation"]["nullable"])
        self.assertIn("TANH", fields["gate_stack_activation"]["choices"])
        self.assertEqual(fields["halting_stack_independent_flag"]["type"], "bool")
        self.assertFalse(fields["halting_stack_independent_flag"]["default"])
        self.assertNotIn("halting_hidden_dim", fields)
        self.assertNotIn("halting_layer_norm_position", fields)
        self.assertNotIn("halting_bias_flag", fields)
        self.assertEqual(
            fields["recurrent_halting_stack_independent_flag"]["type"],
            "bool",
        )
        self.assertFalse(
            fields["recurrent_halting_stack_independent_flag"]["default"],
        )
        self.assertNotIn("recurrent_halting_hidden_dim", fields)
        self.assertNotIn("recurrent_halting_layer_norm_position", fields)
        self.assertNotIn("recurrent_halting_bias_flag", fields)
        self.assertEqual(
            fields["halting_stack_last_layer_bias_option"]["default"],
            "DISABLED",
        )
        self.assertTrue(fields["halting_stack_last_layer_bias_option"]["nullable"])
        self.assertIn(
            "DEFAULT",
            fields["halting_stack_last_layer_bias_option"]["choices"],
        )

    def test_config_schema_stack_equivalent_fields_match_canonical_metadata(
        self,
    ) -> None:
        stack_equivalent_suffixes = {
            "hidden_dim",
            "num_layers",
            "activation",
            "layer_norm_position",
            "apply_output_postprocessing_flag",
            "bias_flag",
        }

        for model_name in ("linears/linear", "linears/linear_adaptive"):
            fields = _fields_by_key(config_schema(model_name))
            for field_key, field in fields.items():
                if "_stack_" not in field_key or field_key.startswith("stack_"):
                    continue
                suffix = field_key.split("_stack_", 1)[1]
                if suffix not in stack_equivalent_suffixes:
                    continue
                canonical_key = f"stack_{suffix}"
                if canonical_key not in fields:
                    continue

                with self.subTest(
                    model_name=model_name,
                    field_key=field_key,
                    canonical_key=canonical_key,
                ):
                    canonical = fields[canonical_key]
                    self.assertEqual(field["type"], canonical["type"])
                    self.assertEqual(field["choices"], canonical["choices"])
                    self.assertEqual(field["key"].lower(), field_key)
                    self.assertNotEqual(field["section"], canonical["section"])

        linear_fields = _fields_by_key(config_schema("linears/linear"))
        self.assertEqual(
            linear_fields["hidden_dim"]["default"],
            linear_config.HIDDEN_DIM,
        )
        self.assertFalse(linear_fields["hidden_dim"]["nullable"])
        self.assertIsNone(linear_fields["gate_stack_hidden_dim"]["default"])
        self.assertTrue(linear_fields["gate_stack_hidden_dim"]["nullable"])
        self.assertTrue(
            linear_fields["stack_apply_output_postprocessing_flag"]["default"]
        )
        self.assertFalse(
            linear_fields["stack_apply_output_postprocessing_flag"]["nullable"]
        )
        self.assertIsNone(
            linear_fields["memory_stack_apply_output_postprocessing_flag"]["default"]
        )
        self.assertTrue(
            linear_fields["memory_stack_apply_output_postprocessing_flag"]["nullable"]
        )

    def test_parse_config_value_supports_nullable_memory_primitives(self) -> None:
        self.assertEqual(
            parse_config_value(
                linear_config,
                "MEMORY_TEST_TIME_TRAINING_LEARNING_RATE",
                "0.02",
            ),
            0.02,
        )
        self.assertEqual(
            parse_config_value(
                linear_config,
                "MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS",
                "2",
            ),
            2,
        )
        self.assertIsNone(
            parse_config_value(
                linear_config,
                "MEMORY_TEST_TIME_TRAINING_LEARNING_RATE",
                "None",
            )
        )
        self.assertIs(
            parse_config_value(
                linear_config,
                "MEMORY_OPTION",
                "WeightedDynamicMemoryConfig",
            ),
            WeightedDynamicMemoryConfig,
        )

    def test_parse_config_value_supports_none_for_nullable_overrides(self) -> None:
        self.assertIsNone(
            parse_config_value(linear_config, "MEMORY_STACK_HIDDEN_DIM", "None")
        )
        self.assertIsNone(
            parse_config_value(
                linear_config,
                "MEMORY_STACK_DROPOUT_PROBABILITY",
                "None",
            )
        )
        self.assertIsNone(
            parse_config_value(linear_config, "MEMORY_STACK_ACTIVATION", "None")
        )
        self.assertIsNone(
            parse_config_value(
                linear_config,
                "MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG",
                "None",
            )
        )
        self.assertIs(
            parse_config_value(linear_config, "GATE_OPTION", "MULTIPLIER"),
            LayerGateOptions.MULTIPLIER,
        )
        self.assertIs(
            parse_config_value(linear_config, "RECURRENT_GATE_OPTION", "MULTIPLIER"),
            LayerGateOptions.MULTIPLIER,
        )
        self.assertIs(
            parse_config_value(linear_config, "GATE_OPTION", "ADDITION"),
            LayerGateOptions.ADDITION,
        )
        with self.assertRaises(ConfigValueError):
            parse_config_value(linear_config, "GATE_OPTION", "INTERPOLATION")
        self.assertIs(
            parse_config_value(linear_config, "GATE_ACTIVATION", "TANH"),
            ActivationOptions.TANH,
        )
        self.assertIsNone(parse_config_value(linear_config, "GATE_OPTION", "None"))

    def test_parse_config_value_supports_residual_config_classes_only(self) -> None:
        self.assertIs(
            parse_config_value(
                linear_config,
                "STACK_RESIDUAL_CONNECTION_OPTION",
                "WeightedResidualConfig",
            ),
            WeightedResidualConfig,
        )
        with self.assertRaises(ConfigValueError):
            parse_config_value(
                linear_config,
                "STACK_RESIDUAL_CONNECTION_OPTION",
                "RESIDUAL",
            )

    def test_config_schema_marks_preset_owned_fields_locked(self) -> None:
        baseline_fields = _fields_by_key(config_schema("linears/linear", "baseline"))
        gating_fields = _fields_by_key(config_schema("linears/linear", "gating"))

        self.assertFalse(baseline_fields["stack_gate_flag"]["locked"])
        self.assertTrue(gating_fields["stack_gate_flag"]["locked"])
        self.assertEqual(gating_fields["stack_gate_flag"]["lockedValue"], True)
        self.assertEqual(
            gating_fields["stack_gate_flag"]["lockedReason"],
            (
                "Locked by the GATING preset because this preset locks "
                "`stack_gate_flag`."
            ),
        )

    def test_config_schema_locks_adaptive_component_flags_for_presets(self) -> None:
        fields = _fields_by_key(config_schema("linears/linear_adaptive", "full-stack"))

        expected_locked_fields = {
            "weight_option_flag": True,
            "weight_option": "DualModelDynamicWeightConfig",
            "bias_option_flag": True,
            "bias_option": "AdditiveDynamicBiasConfig",
            "diagonal_option_flag": True,
            "diagonal_option": "CombinedDynamicDiagonalConfig",
            "mask_option_flag": True,
            "row_mask_option": "WeightInformedScoreAxisMaskConfig",
        }
        for field_key, locked_value in expected_locked_fields.items():
            with self.subTest(field_key=field_key):
                self.assertTrue(fields[field_key]["locked"])
                self.assertEqual(fields[field_key]["lockedValue"], locked_value)
                self.assertIn("FULL_STACK preset", fields[field_key]["lockedReason"])
                self.assertIn(f"`{field_key}`", fields[field_key]["lockedReason"])

    def test_search_space_schema_exposes_linear_axes(self) -> None:
        axes = _axes_by_key(search_space_schema("linears/linear", "baseline"))

        self.assertIn("learning_rate", axes)
        self.assertIn("hidden_dim", axes)
        self.assertIn("stack_activation", axes)
        self.assertEqual(axes["hidden_dim"]["section"], "Global")
        self.assertEqual(axes["hidden_dim"]["type"], "int")
        self.assertEqual(
            axes["hidden_dim"]["values"],
            [16, 32, 64, 128, 256, 512],
        )
        self.assertEqual(axes["stack_activation"]["type"], "enum")
        self.assertIn("GELU", axes["stack_activation"]["values"])
        self.assertFalse(axes["hidden_dim"]["locked"])

    def test_search_space_schema_serializes_axis_values(self) -> None:
        linear_axes = _axes_by_key(search_space_schema("linears/linear", "baseline"))
        adaptive_axes = _axes_by_key(
            search_space_schema("linears/linear_adaptive", "baseline")
        )

        self.assertEqual(
            linear_axes["hidden_dim"]["values"],
            [16, 32, 64, 128, 256, 512],
        )
        self.assertEqual(
            linear_axes["stack_activation"]["values"],
            ["RELU", "LEAKY_RELU", "ELU", "GELU", "TANH"],
        )
        self.assertFalse(
            any(key.endswith("_layer_adaptive_flag") for key in adaptive_axes)
        )
        self.assertEqual(
            adaptive_axes["adaptive_generator_stack_num_layers"]["values"],
            [1, 2, 3],
        )

    def test_search_space_schema_marks_preset_owned_axes_locked(self) -> None:
        axes = _axes_by_key(search_space_schema("linears/linear", "post-norm"))

        self.assertTrue(axes["layer_norm_position"]["locked"])
        self.assertEqual(axes["layer_norm_position"]["lockedValue"], "AFTER")
        self.assertEqual(
            axes["layer_norm_position"]["lockedByPresets"],
            ["POST_NORM"],
        )
        self.assertEqual(len(axes["layer_norm_position"]["lockReasons"]), 1)
        self.assertEqual(
            axes["layer_norm_position"]["lockedReason"],
            (
                "Locked by the POST_NORM preset because this preset locks "
                "`layer_norm_position`."
            ),
        )

    def test_search_space_schema_locks_union_of_selected_presets(self) -> None:
        axes = _axes_by_key(
            search_space_schema(
                "linears/linear_adaptive",
                "baseline",
                ["single-model-weight", "additive-bias"],
            )
        )

        self.assertTrue(axes["weight_option"]["locked"])
        self.assertEqual(
            axes["weight_option"]["lockedByPresets"],
            ["SINGLE_MODEL_WEIGHT"],
        )
        self.assertEqual(
            axes["weight_option"]["lockedValue"],
            "SingleModelDynamicWeightConfig",
        )
        self.assertTrue(axes["bias_option"]["locked"])
        self.assertEqual(
            axes["bias_option"]["lockedByPresets"],
            ["ADDITIVE_BIAS"],
        )
        self.assertEqual(
            axes["bias_option"]["lockedValue"],
            "AdditiveDynamicBiasConfig",
        )
        self.assertFalse(axes["hidden_dim"]["locked"])
        self.assertNotIn("weight_option_flag", axes)
        self.assertNotIn("bias_option_flag", axes)


if __name__ == "__main__":
    unittest.main()
