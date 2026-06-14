# SPDX-FileCopyrightText: (c) 2026 Tenstorrent AI ULC
#
# SPDX-License-Identifier: Apache-2.0
import pytest
import vllm
from conftest import assert_output_coherent, check_host_memory


@pytest.mark.push
@pytest.mark.tensor_parallel
@pytest.mark.dual_chip
@pytest.mark.parametrize("model_name", ["meta-llama/Llama-3.2-3B"])
def test_tensor_parallel_generation_n300(model_name: str):
    prompts = [
        "I like taking walks in the",
    ]
    sampling_params = vllm.SamplingParams(temperature=0.8, top_p=0.95, max_tokens=32)
    llm_args = {
        "model": model_name,
        "max_num_batched_tokens": 32,
        "max_num_seqs": 1,
        "max_model_len": 32,
        "gpu_memory_utilization": 0.002,
        "additional_config": {
            "enable_const_eval": False,
            "min_context_len": 32,
            "enable_tensor_parallel": True,
        },
    }
    llm = vllm.LLM(**llm_args)

    output_text = llm.generate(prompts, sampling_params)[0].outputs[0].text
    print(f"prompt: {prompts[0]}, output: {output_text}")
    assert_output_coherent(output_text)


@pytest.mark.push
@pytest.mark.tensor_parallel
@pytest.mark.llmbox
@pytest.mark.parametrize(
    ["model_name"],
    [
        pytest.param("Qwen/Qwen3-0.6B"),
    ],
)
@pytest.mark.parametrize("use_2d_mesh", [True, False])
def test_tensor_parallel_generation_llmbox_small(
    model_name: str,
    use_2d_mesh: bool,
):
    prompts = [
        "Continue in English: I like taking walks in the",
    ]
    sampling_params = vllm.SamplingParams(temperature=0.8, top_p=0.95, max_tokens=32)
    llm_args = {
        "model": model_name,
        "max_num_batched_tokens": 32,
        "max_num_seqs": 1,
        "max_model_len": 32,
        "gpu_memory_utilization": 0.002,
        "additional_config": {
            "min_context_len": 32,
            "enable_tensor_parallel": True,
            "use_2d_mesh": use_2d_mesh,
        },
    }
    llm = vllm.LLM(**llm_args)

    output_text = llm.generate(prompts, sampling_params)[0].outputs[0].text
    print(f"prompt: {prompts[0]}, output: {output_text}")
    assert_output_coherent(output_text)

    check_host_memory(model_name)


@pytest.mark.nightly
@pytest.mark.tensor_parallel
@pytest.mark.llmbox
@pytest.mark.parametrize(
    ["model_name", "enable_const_eval", "experimental_weight_dtype", "use_2d_mesh"],
    [
        pytest.param("Qwen/Qwen3-32B", False, "", True),
        pytest.param("Qwen/Qwen3-8B", False, "", False),
        pytest.param("meta-llama/Llama-3.1-70B", True, "bfp_bf8", True),
    ],
)
def test_tensor_parallel_generation_llmbox_large(
    model_name: str,
    enable_const_eval: bool,
    experimental_weight_dtype: str,
    use_2d_mesh: bool,
):
    prompts = [
        "I like taking walks in the",
    ]
    sampling_params = vllm.SamplingParams(temperature=0.8, top_p=0.95, max_tokens=32)
    llm_args = {
        "model": model_name,
        "max_num_batched_tokens": 32,
        "max_num_seqs": 1,
        "max_model_len": 32,
        "gpu_memory_utilization": 0.002,
        "additional_config": {
            "enable_const_eval": enable_const_eval,
            "min_context_len": 32,
            "enable_tensor_parallel": True,
            "experimental_weight_dtype": experimental_weight_dtype,
            "use_2d_mesh": use_2d_mesh,
        },
    }
    llm = vllm.LLM(**llm_args)

    output_text = llm.generate(prompts, sampling_params)[0].outputs[0].text
    print(f"prompt: {prompts[0]}, output: {output_text}")
    assert_output_coherent(output_text)

    check_host_memory(model_name)


@pytest.mark.nightly
@pytest.mark.tensor_parallel
@pytest.mark.galaxy_wh_6u
@pytest.mark.xfail(
    strict=True,
    reason=(
        "sdpa_decode tree-reduction limit (max 64 cores/head) exceeded after the "
        "QKV sharding axis swap to ('model', 'batch') in this PR. With kv_heads=8 "
        "split 8-way on galaxy_wh_6u's (4, 8) mesh model axis, each device gets "
        "1 KV head and the kernel allocates the full 72-core grid to it. Fixed "
        "in tt-metal by #44617 (L1-safe defaults for paged SDPA decode, "
        "max_cores_per_head_batch=1). Remove this xfail once tt-mlir uplifts "
        "past tt-metal 5cd3b7a (open uplift PRs: tt-mlir #8484, #8597)."
    ),
)
@pytest.mark.parametrize(
    ["model_name", "enable_const_eval", "experimental_weight_dtype", "use_2d_mesh"],
    [pytest.param("mistralai/Mistral-Large-Instruct-2411", True, "bfp_bf8", True)],
)
def test_tensor_parallel_generation_galaxy_wh_6u_large(
    model_name: str,
    enable_const_eval: bool,
    experimental_weight_dtype: str,
    use_2d_mesh: bool,
):
    inputs = ["How many days ago was Mistral founded?"]

    sampling_params = vllm.SamplingParams(temperature=0.8, top_p=0.95, max_tokens=16)
    llm_args = {
        "model": model_name,
        "max_num_batched_tokens": 32,
        "max_num_seqs": 1,
        "max_model_len": 32,
        "gpu_memory_utilization": 0.02,
        "additional_config": {
            "enable_const_eval": enable_const_eval,
            "min_context_len": 64,
            "enable_tensor_parallel": True,
            "experimental_weight_dtype": experimental_weight_dtype,
            "use_2d_mesh": use_2d_mesh,
        },
    }
    llm = vllm.LLM(**llm_args)

    output_text = llm.generate(inputs, sampling_params)[0].outputs[0].text
    print("output: ", output_text)
    assert_output_coherent(output_text)

    check_host_memory(model_name)


@pytest.mark.nightly
@pytest.mark.tensor_parallel
@pytest.mark.llmbox
def test_tensor_parallel_generation_llmbox_deepseek_v32_single_layer():
    """Single-layer DeepSeek-V3.2 (DSA) compile/run smoke on llmbox.

    Exercises the DeepSeek Sparse Attention path end-to-end: the
    ``num_hidden_layers=1`` override compiles only decoder layer 0, which is a
    dense layer (``n_dense_layers=1``) so this brings up MLA + the lightning
    indexer (see vllm_tt/attention_dsa.py) without the MoE experts.

    NOTE: one layer cannot produce coherent text, so this asserts only that the
    DSA graph compiles, runs, and emits the requested tokens — NOT
    ``assert_output_coherent``.

    Uses ``load_format="dummy"`` (random weights): the full DeepSeek-V3.2
    checkpoint is ~600 GB of block-wise FP8, and a single layer is gibberish
    regardless, so this validates the DSA compile/run path on device without the
    download. Swap to real weights to sanity-check numerics once available.
    """
    model_name = "deepseek-ai/DeepSeek-V3.2-Exp"
    prompts = ["I like taking walks in the"]
    max_tokens = 16
    sampling_params = vllm.SamplingParams(
        temperature=0.0, top_p=1.0, max_tokens=max_tokens
    )
    llm_args = {
        "model": model_name,
        "load_format": "dummy",
        # DeepSeek-V3.2 ships block-wise FP8, but vLLM's FP8 linear kernel has no
        # OOT-platform entry (KeyError on PlatformEnum.OOT). With dummy weights we
        # don't need the real FP8 checkpoint, so drop the quantization_config and
        # build the layer unquantized in bf16. (Real FP8 support on TT is a
        # separate effort, orthogonal to DSA attention.)
        "hf_overrides": {"quantization_config": None},
        "max_num_batched_tokens": 32,
        "max_num_seqs": 1,
        "max_model_len": 32,
        "gpu_memory_utilization": 0.1,
        "additional_config": {
            # Compile only the first (dense) decoder layer.
            "num_hidden_layers": 1,
            "min_context_len": 32,
            "enable_tensor_parallel": True,
            # DeepSeek-V3.2 forces chunked prefill / prefix caching off (MLA);
            # keep const-eval off to avoid storing the full model per graph.
            "enable_const_eval": False,
        },
    }
    llm = vllm.LLM(**llm_args)

    output = llm.generate(prompts, sampling_params)[0].outputs[0]
    print(f"prompt: {prompts[0]}, output: {output.text!r}")
    # A single layer is gibberish; only assert the path ran and produced tokens.
    assert len(output.token_ids) > 0, "DSA single-layer run produced no tokens"


@pytest.mark.nightly
@pytest.mark.tensor_parallel
@pytest.mark.bhqb
@pytest.mark.parametrize(
    ["enable_const_eval", "experimental_weight_dtype", "use_2d_mesh"],
    [
        pytest.param(True, "", False),
    ],
)
def test_tensor_parallel_generation_bhqb_gemma4_31b(
    enable_const_eval: bool,
    experimental_weight_dtype: str,
    use_2d_mesh: bool,
):
    model_name = "google/gemma-4-31B-it"

    messages = [[{"role": "user", "content": "Describe Tenstorrent in one sentence."}]]
    sampling_params = vllm.SamplingParams(temperature=0.0, top_p=1.0, max_tokens=32)
    llm_args = {
        "model": model_name,
        # Text-only path on a multimodal model: zero every modality so the
        # mm-encoder graph doesn't compile the vision tower at all.
        "limit_mm_per_prompt": {"image": 0, "video": 0, "audio": 0},
        # Gemma-4 mm enforces a floor from MultiModalBudget regardless of
        # limit_mm_per_prompt; 2560 clears the video-frame floor of 2496.
        "max_num_batched_tokens": 2560,
        "max_num_seqs": 1,
        "max_model_len": 128,
        "gpu_memory_utilization": 0.1,
        "additional_config": {
            "enable_const_eval": enable_const_eval,
            "min_context_len": 32,
            "enable_tensor_parallel": True,
            "experimental_weight_dtype": experimental_weight_dtype,
            "use_2d_mesh": use_2d_mesh,
            "cpu_sampling": False,
            "flat_model_io": True,
        },
    }
    llm = vllm.LLM(**llm_args)

    output_text = llm.chat(messages, sampling_params)[0].outputs[0].text
    print(f"output: {output_text}")
    assert_output_coherent(output_text)

    check_host_memory(model_name)
