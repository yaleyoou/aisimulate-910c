import json

import pytest

from aisimulate_core.sdk.config_builders import build_model_config
from aisimulate_core.sdk.engine import _engine_config_dict
from aisimulate_core.sdk.errors import InvalidEngineConfigurationError, PerfDataNotAvailableError
from aisimulate_core.sdk.fpm_config import OpLevelCompileConfig
from aisimulate_core.sdk.models import get_model
from tests.unit.sdk.ascend_fixtures import write_glm52_modelslim

pytestmark = pytest.mark.unit


@pytest.fixture(scope="module")
def model_path(tmp_path_factory):
    return write_glm52_modelslim(tmp_path_factory.mktemp("ascend-forward-model"))


def configuration():
    return build_model_config(
        tp_size=8,
        pp_size=1,
        attention_dp_size=2,
        moe_tp_size=1,
        moe_ep_size=16,
        gemm_quant_mode="w8a8",
        moe_quant_mode="w8a8_dynamic",
        kvcache_quant_mode="bfloat16",
        system="ascend910c",
    )


def flattened(operations):
    output = {}

    def visit(spec):
        kind, value = next(iter(spec.items()))
        if kind == "Overlap":
            for child in value["group_a"] + value["group_b"]:
                visit(child)
        elif kind == "TokenScale":
            visit(value["op"])
        else:
            output[value["name"]] = (kind, value)

    for operation in operations:
        visit(json.loads(operation._spec_json()))
    return output


def test_resident_inventory_matches_loaded_united_parameters(model_path):
    model = get_model(model_path, configuration(), "sglang")
    assert model.get_resident_weights_bytes() == 52_471_997_948
    context, generation = flattened(model.context_ops), flattened(model.generation_ops)
    assert context["context_indexer"][1]["scale_factor"] == 21
    assert context["context_attention"][1]["scale_factor"] == 78
    assert context["context_dense_gate_up"][1]["scale_factor"] == 3
    assert context["context_routed_experts"][1]["scale_factor"] == 75
    assert context["context_rope_cache"][1]["scale_factor"] == 2
    assert context["context_rope_cache"][1]["resident_copies"] == 1
    assert context["context_dense_global_sums"][1]["scale_factor"] == 6
    assert generation["generation_dense_input_gather"][1]["scale_factor"] == 3
    assert generation["generation_dense_output_reduce_scatter"][1]["scale_factor"] == 3
    assert generation["generation_sparse_reduce_scatter"][1]["scale_factor"] == 75
    assert generation["generation_dense_attention_reduce_scatter"][1]["scale_factor"] == 3
    assert context["context_logits_gather"][1]["token_axis"] == "requests"
    assert context["context_logits_finalize"][1]["token_axis"] == "requests"


def test_decode_padding_preserves_global_dense_and_rank_local_expert_shapes(model_path):
    model = get_model(model_path, configuration(), "sglang")
    decoded = [json.loads(operation._spec_json()) for operation in model.generation_ops]
    dense = next(
        spec["TokenScale"]
        for spec in decoded
        if "TokenScale" in spec
        and spec["TokenScale"]["op"].get("AscendLinear", {}).get("name") == "generation_dense_gate_up"
    )
    assert dense["numerator"] == 2 and dense["denominator"] == 1
    assert dense["op"]["AscendLinear"]["token_multiple"] == 16
    ops = flattened(model.generation_ops)
    assert ops["generation_shared_gate_up"][1]["token_split"] == 8
    assert ops["generation_moe_dispatch"][1]["input_token_multiple"] == 8
    assert ops["generation_indexer_weights"][1]["key"]["quant_mode"] == "float32_bfloat16"
    assert ops["generation_final_norm"][1]["token_split"] == 1
    assert ops["generation_sparse_input_norms"][1]["token_split"] == 8


def test_tp16_matches_observed_single_dp_boundaries_and_graph_padding(model_path):
    config = configuration()
    config.tp_size, config.attention_dp_size = 16, 1
    model = get_model(model_path, config, "sglang")
    assert model.get_resident_weights_bytes() == 51_292_091_900
    for phase, operations in (("context", model.context_ops), ("generation", model.generation_ops)):
        ops = flattened(operations)
        assert ops[phase + "_dense_global_sums"][1]["scale_factor"] == 6
        assert ops[phase + "_dense_post_norm"][1]["key"]["role"] == "add_rms_bias"
        assert phase + "_dense_residual_add" not in ops
        assert phase + "_dense_input_gather" not in ops
        assert ops[phase + "_sparse_reduce_scatter"][1]["scale_factor"] == 75
        assert ops[phase + "_sparse_output_gather"][1]["scale_factor"] == 75
    generated = flattened(model.generation_ops)
    assert generated["generation_attention"][1]["graph_buckets"] == [16, 32]
    assert generated["generation_sparse_output_gather"][1]["elements_per_token"] == 6144
    assert generated["generation_sparse_output_gather"][1]["token_split"] == 16
    assert generated["generation_logits_gemm"][1]["key"]["n"] == 9680
    assert generated["generation_logits_gemm"][1]["token_multiple"] == 16


def test_tensor_moe_matches_loaded_weights_and_observed_all_reduce_boundaries(model_path):
    config = configuration()
    config.tp_size, config.attention_dp_size = 16, 1
    config.moe_tp_size, config.moe_ep_size = 16, 1
    model = get_model(model_path, config, "sglang")
    assert model.get_resident_weights_bytes() == 49_300_283_900
    assert model.execution_assumptions["moe_a2a_backend"] == "none"
    assert model.execution_assumptions["prefill_shared_expert_overlap"] is False
    assert all("Overlap" not in json.loads(operation._spec_json()) for operation in model.context_ops)
    assert any("Overlap" in json.loads(operation._spec_json()) for operation in model.generation_ops)
    for phase, operations in (("context", model.context_ops), ("generation", model.generation_ops)):
        ops = flattened(operations)
        assert ops[phase + "_routed_experts"][0] == "AscendMoeTensor"
        assert ops[phase + "_routed_experts"][1]["key"]["intermediate_size"] == 128
        assert ops[phase + "_shared_gate_up"][1]["key"]["n"] == 256
        assert ops[phase + "_shared_down"][1]["key"]["k"] == 128
        assert ops[phase + "_shared_gate_up"][1]["token_split"] == 1
        assert ops[phase + "_final_norm"][1]["key"]["role"] == "add_rms_bias"
        assert phase + "_final_residual_add" not in ops
        assert all(kind != "AscendDeepEp" for kind, _ in ops.values())
        assert (
            sum(
                spec["scale_factor"]
                for kind, spec in ops.values()
                if kind == "Hccl" and spec["key"]["operation"] == "all_reduce"
            )
            == 157
        )


@pytest.mark.parametrize("local_tp,attention_dp,resident", [(8, 2, 50_480_189_948), (4, 4, 52_840_002_044)])
def test_tensor_moe_with_attention_dp_matches_observed_global_ffn_boundaries(
    model_path, local_tp, attention_dp, resident
):
    config = configuration()
    config.tp_size, config.attention_dp_size = local_tp, attention_dp
    config.moe_tp_size, config.moe_ep_size = 16, 1
    model = get_model(model_path, config, "sglang")
    assert model.get_resident_weights_bytes() == resident
    context, generation = flattened(model.context_ops), flattened(model.generation_ops)
    assert context["context_sparse_global_sums"][1]["scale_factor"] == 150
    assert context["context_sparse_global_sums"][1]["key"]["num_ranks"] == 16
    assert generation["generation_sparse_attention_reduce_scatter"][1]["key"]["num_ranks"] == local_tp
    assert generation["generation_sparse_input_gather"][1]["key"]["num_ranks"] == 16
    assert generation["generation_sparse_output_reduce_scatter"][1]["key"]["num_ranks"] == 16
    assert generation["generation_sparse_output_gather"][1]["key"]["num_ranks"] == local_tp
    assert generation["generation_sparse_post_norm"][1]["key"]["role"] == "rms_bias"
    assert generation["generation_routed_experts"][1]["input_token_multiple"] == 8 * attention_dp
    assert generation["generation_shared_gate_up"][1]["token_multiple"] == 8 * attention_dp
    assert generation["generation_shared_gate_up"][1]["key"]["n"] == 256
    assert generation["generation_shared_down"][1]["key"]["k"] == 128


@pytest.mark.parametrize("local_tp,attention_dp", [(4, 8), (8, 4), (16, 2)])
def test_tensor_moe_global32_uses_measured_64_wide_shards(model_path, local_tp, attention_dp):
    config = configuration()
    config.tp_size, config.attention_dp_size = local_tp, attention_dp
    config.moe_tp_size, config.moe_ep_size = 32, 1
    model = get_model(model_path, config, "sglang")
    ops = flattened(model.generation_ops)
    assert ops["generation_routed_experts"][1]["key"]["intermediate_size"] == 64
    assert ops["generation_shared_down"][1]["key"]["k"] == 64
    assert ops["generation_sparse_input_gather"][1]["key"]["num_ranks"] == 32
    assert ops["generation_sparse_output_reduce_scatter"][1]["key"]["num_ranks"] == 32


def test_dcp_composes_storage_once_and_matches_observed_split_kv_pool(model_path):
    config = configuration()
    config.dcp_size = 2
    model = get_model(model_path, config, "sglang")
    for operations in (model.context_ops, model.generation_ops):
        entries = flattened(operations)
        attention = [spec for kind, spec in entries.values() if kind == "AscendDcpAttention"]
        assert {(item["key"]["remap_topk"], item["scale_factor"]) for item in attention} == {
            (True, 21.0),
            (False, 57.0),
        }
        assert not any(
            kind == "AscendVector" and spec["key"]["role"] == "cache_scatter" for kind, spec in entries.values()
        )
        assert all(
            spec["key"]["operation"] == "lightning_indexer"
            for kind, spec in entries.values()
            if kind == "AscendAttention"
        )
    assert model.get_resident_weights_bytes() == 52_471_997_948
    assert model.get_kvcache_rank_bytes_per_sequence(1) == 64_896
    assert model.get_kvcache_pool_overhead_bytes() == 16_613_376
    assert model.get_kvcache_rank_bytes_per_sequence(49_664) + model.get_kvcache_pool_overhead_bytes() == 3_239_608_320
    assert model.get_kvcache_rank_batch_capacity(3_239_608_320, 32) == 49_664
    assert model.get_kvcache_rank_batch_capacity(3_239_608_319, 32) == 49_408


def test_attention_tp1_has_no_local_collective_and_keeps_terminal_residual_for_norm(model_path):
    config = configuration()
    config.tp_size, config.attention_dp_size, config.moe_ep_size = 1, 32, 32
    model = get_model(model_path, config, "sglang")
    for phase, operations in (("context", model.context_ops), ("generation", model.generation_ops)):
        entries = flattened(operations)
        assert all(spec["key"]["num_ranks"] > 1 for kind, spec in entries.values() if kind == "Hccl")
        assert phase + "_embedding_all_reduce" not in entries
        assert phase + "_sparse_output_gather" not in entries
        assert phase + "_logits_gather" not in entries
        assert phase + "_final_residual_add" not in entries
        assert entries[phase + "_final_norm"][1]["key"]["role"] == "add_rms_bias"
        assert entries[phase + "_q_b"][1]["key"]["n"] == 16384
        assert entries[phase + "_logits_gemm"][1]["key"]["n"] == 154880


def test_explicit_serial_shared_experts_survive_saved_engine_identity(model_path):
    config = configuration()
    config.op_level_config = OpLevelCompileConfig(
        {"ascend": {"shared_expert_overlap": False}}, system="ascend910c", backend="sglang"
    )
    model = get_model(model_path, config, "sglang")
    assert all("Overlap" not in json.loads(operation._spec_json()) for operation in model.generation_ops)
    assert model.get_resident_weights_bytes() == 52_471_997_948
    engine = _engine_config_dict(
        model=model,
        model_path=model_path,
        system="ascend910c",
        backend="sglang",
        backend_version="0.5.22",
        kv_block_size=128,
        systems_path=None,
        nextn=0,
    )
    saved = json.loads(engine["extra"]["estimator_config"])
    assert saved["op_level"]["ascend"] == {
        "shared_expert_overlap": False,
        "routing": "balanced",
        "kv_transfer_page_layout": "contiguous",
    }


def test_model_name_and_w8a8_label_cannot_replace_checkpoint_metadata():
    with pytest.raises(InvalidEngineConfigurationError, match="quant_model_description"):
        get_model("zai-org/GLM-5.2", configuration(), "sglang")


def test_default_search_requires_the_audited_checkpoint(model_path):
    from aisimulate_core.sdk.models.ascend_glm52 import ascend_glm52_default_parallel_shapes
    from aisimulate_core.sdk.utils import get_model_config_from_model_path

    raw = get_model_config_from_model_path(model_path)["raw_config"]
    assert ascend_glm52_default_parallel_shapes(raw) == (
        (1, 16, 1, 16, 1),
        (2, 8, 1, 16, 1),
        (4, 4, 1, 16, 1),
        (8, 2, 1, 16, 1),
        (16, 1, 1, 16, 1),
        (1, 32, 1, 32, 1),
        (2, 16, 1, 32, 1),
        (4, 8, 1, 32, 1),
        (8, 4, 1, 32, 1),
        (16, 2, 1, 32, 1),
        (1, 16, 16, 1, 1),
        (2, 8, 16, 1, 1),
        (4, 4, 16, 1, 1),
        (8, 2, 16, 1, 1),
        (16, 1, 16, 1, 1),
        (1, 32, 32, 1, 1),
        (2, 16, 32, 1, 1),
        (4, 8, 32, 1, 1),
        (8, 4, 32, 1, 1),
        (16, 2, 32, 1, 1),
    )
    with pytest.raises(InvalidEngineConfigurationError, match="quant_model_description"):
        ascend_glm52_default_parallel_shapes({**raw, "modelslim_metadata": None})


def transfer_model(model_path, role, **overrides):
    from aisimulate_core.sdk.rust_engine_step import RustForwardPassPerfModel

    return RustForwardPassPerfModel.best_available(
        {
            "model": model_path,
            "system": "ascend910c",
            "backend": "sglang",
            "backend_version": "0.5.22",
            "worker_type": role,
            "tp": 8,
            "attention_dp": 2,
            "moe_tp_size": 1,
            "moe_ep_size": 16,
            "kv_block_size": 128,
            "gemm_quant_mode": "w8a8",
            "moe_quant_mode": "w8a8_dynamic",
            "kvcache_quant_mode": "bfloat16",
            "fmha_quant_mode": "bfloat16",
            "estimation_mode": "op_level",
            **overrides,
        }
    )


def test_canonical_pd_model_selects_measured_mapping_and_rejects_unknown_geometry(model_path):
    source = transfer_model(model_path, "prefill")
    target = transfer_model(model_path, "decode")
    metadata = source.kv_transfer_metadata(target)
    assert metadata["key"] == {"source_tp": 8, "destination_tp": 8, "page_layout": "contiguous"}
    assert metadata["bytes_per_token_per_replica"] == 109824
    assert source.estimate_kv_transfer_time_ms(target, 0) == 0
    latency = source.estimate_kv_transfer_time_ms(target, 8192)
    assert 7 < latency < 9
    assert source.estimate_kv_transfer_time_ms(target, 8191) == latency
    with pytest.raises(PerfDataNotAvailableError, match="outside measured"):
        source.estimate_kv_transfer_time_ms(target, 32768)
    with pytest.raises(ValueError, match="matching Ascend"):
        target.estimate_kv_transfer_time_ms(source, 8192)
    multi_node = transfer_model(model_path, "decode", attention_dp=4, moe_ep_size=32)
    assert source.estimate_kv_transfer_time_ms(multi_node, 8192) == latency
    assert source.kv_transfer_metadata(multi_node)["key"] == metadata["key"]
    fragmented = transfer_model(
        model_path,
        "decode",
        estimator_config={"op_level": {"ascend": {"kv_transfer_page_layout": "fragmented"}}},
    )
    with pytest.raises(ValueError, match="matching role page-layout"):
        source.estimate_kv_transfer_time_ms(fragmented, 8192)
