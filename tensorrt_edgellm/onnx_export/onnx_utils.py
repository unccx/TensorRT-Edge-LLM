# SPDX-FileCopyrightText: Copyright (c) 2025-2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
# SPDX-License-Identifier: Apache-2.0
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
# http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

import copy
import os
import time

import onnx
import onnx_graphsurgeon as gs
import torch
import torch.nn as nn

from ..common import ONNX_OPSET_VERSION
from ..llm_models.layers.int4_gemm_plugin import int4_dq_gemm_to_plugin
from ..llm_models.models.llm_model import EdgeLLMModelForCausalLM


def is_int4_awq_quantized(model: nn.Module) -> bool:
    """Check if the model is quantized in INT4 mode."""
    for _, module in model.named_modules():
        if (hasattr(module, "input_quantizer")
                and hasattr(module, "weight_quantizer")
                and module.weight_quantizer._num_bits == 4
                and module.input_quantizer._disabled):
            return True
    return False


def is_fp4_quantized(model: nn.Module) -> bool:
    """Check if the model is quantized in NVFP4 mode."""
    for _, module in model.named_modules():
        if (hasattr(module, "input_quantizer")
                and module.input_quantizer.block_sizes
                and module.input_quantizer.block_sizes.get("scale_bits",
                                                           None) == (4, 3)):
            return True
    return False


def is_mxfp8_quantized(model: nn.Module) -> bool:
    """Check if the model is quantized in MXFP8 mode."""
    for _, module in model.named_modules():
        if (hasattr(module, "input_quantizer")
                and module.input_quantizer.block_sizes
                and module.input_quantizer.block_sizes.get("scale_bits",
                                                           None) == (8, 0)):
            return True
    return False


def is_fp8_quantized(model: nn.Module) -> bool:
    """Check if the model is quantized in FP8 mode but not MXFP8."""
    for _, module in model.named_modules():
        if (hasattr(module, "input_quantizer")
                and module.input_quantizer._num_bits == (4, 3)
                and hasattr(module, "weight_quantizer")
                and module.weight_quantizer._num_bits
                == (4, 3)) and not is_mxfp8_quantized(module):
            return True
    return False


def untie_nvfp4_lm_head_initializer(model: onnx.ModelProto) -> onnx.ModelProto:
    """Untie the weights of the nvFP4 quantized LM head from embed_tokens.weight.
    """
    LM_HEAD_WEIGHT_NAME = "lm_head.weight"
    EMBED_TOKENS_WEIGHT_NAME = "embed_tokens.weight"

    lmhead_weight_quantizer = None
    for node in model.graph.node:
        if node.name == "/lm_head/weight_quantizer/TRT_FP4QDQ":
            lmhead_weight_quantizer = node
            break
    if lmhead_weight_quantizer is None:
        raise ValueError(
            "Target node '/lm_head/weight_quantizer/TRT_FP4QDQ' not found in model.graph.node"
        )

    # If tied to embed, create a duplicate initializer and rewire
    if lmhead_weight_quantizer.input and EMBED_TOKENS_WEIGHT_NAME in lmhead_weight_quantizer.input[
            0]:

        # Find the initializer for embed_tokens.weight
        embed_init = None
        for init in model.graph.initializer:
            if EMBED_TOKENS_WEIGHT_NAME in init.name:
                embed_init = init
                break
        if embed_init is None:
            raise ValueError(
                "Initializer containing 'embed_tokens.weight' not found in model.graph.initializer, cannot untie lm_head weights"
            )

        print(
            f"Untying lm_head weights from {lmhead_weight_quantizer.input[0]}, creating a duplicate initializer {LM_HEAD_WEIGHT_NAME}"
        )
        new_init = copy.deepcopy(embed_init)
        new_init.name = LM_HEAD_WEIGHT_NAME
        model.graph.initializer.append(new_init)
        lmhead_weight_quantizer.input[0] = LM_HEAD_WEIGHT_NAME

    return model


def fix_model_int4_output_dtypes(
        onnx_model: onnx.ModelProto) -> onnx.ModelProto:
    """Fix data types for model outputs.
    In modelopt int4 post-processing, some Cast nodes are converted to FP16 instead of FP32 and hidden_states are converted to FP32 instead of FP16, so we need to fix them manually.
    See: https://github.com/NVIDIA/TensorRT-Model-Optimizer/blob/0.37.0/modelopt/onnx/quantization/qdq_utils.py#L1050
    
    Ensures:
    1. For cast->logits or cast->logsoftmax->logits patterns, both cast and logits are FP32
    2. For hidden_states output, it is FP16
    
    Args:
        onnx_model: The ONNX model to fix
    
    Returns:
        The modified ONNX model
    """
    graph = onnx_model.graph

    # Build a map from output name to producer node
    output_to_node = {}
    for node in graph.node:
        for output in node.output:
            output_to_node[output] = node

    # Build a map from output name to graph output
    graph_outputs = {output.name: output for output in graph.output}

    # Helper to update Cast node's "to" attribute
    def set_cast_dtype(node, dtype):
        for attr in node.attribute:
            if attr.name == "to":
                attr.i = dtype
                return

    # Fix logits output to FP32
    if "logits" in graph_outputs:
        logits = graph_outputs["logits"]
        producer = output_to_node.get(logits.name)

        # Check for cast->logsoftmax->logits
        if producer and producer.op_type == "LogSoftmax":
            cast_node = output_to_node.get(producer.input[0])
            if cast_node and cast_node.op_type == "Cast":
                print("Found cast->logsoftmax->logits, ensuring FP32")
                set_cast_dtype(cast_node, 1)
        # Check for cast->logits
        elif producer and producer.op_type == "Cast":
            print("Found cast->logits, ensuring FP32")
            set_cast_dtype(producer, 1)

        # Set logits output type to FP32
        logits.type.tensor_type.elem_type = onnx.TensorProto.FLOAT

    # Fix hidden_states output to FP16
    if "hidden_states" in graph_outputs:
        hidden_states = graph_outputs["hidden_states"]
        producer = output_to_node.get(hidden_states.name)

        if hidden_states.type.tensor_type.elem_type == onnx.TensorProto.FLOAT16:
            print("hidden_states is already FP16")
        else:
            # If producer is Cast, just update it
            if producer and producer.op_type == "Cast":
                print("Updating existing Cast to FP16 for hidden_states")
                set_cast_dtype(producer, 10)
            else:
                # Insert new Cast node
                print("Inserting Cast to FP16 for hidden_states")
                intermediate = f"{hidden_states.name}_pre_fp16"

                # Rename producer's output
                if producer:
                    for i, out in enumerate(producer.output):
                        if out == hidden_states.name:
                            producer.output[i] = intermediate

                # Add Cast node
                cast = onnx.helper.make_node(
                    "Cast",
                    inputs=[intermediate],
                    outputs=[hidden_states.name],
                    to=10,
                    name=f"{hidden_states.name}_cast_fp16")
                graph.node.append(cast)

            # Set hidden_states output type to FP16
            hidden_states.type.tensor_type.elem_type = onnx.TensorProto.FLOAT16

    return onnx_model


def _elide_int8_identity_nodes(onnx_model: onnx.ModelProto) -> onnx.ModelProto:
    """Remove Identity pass-through nodes whose input is an INT8 initializer.

    When ``NemotronHMoEWithSharedExperts`` wraps the plugin, ``torch.onnx.export``
    deduplicates all identical ``hidden_block_scale`` buffers (zeros, INT8, 1×1×1)
    into a single ONNX initializer and fans it out to each plugin instance via
    ``Identity`` nodes.  TRT's QDQ optimizer then complains:
        "Quantized constant ... is only allowed before DQ or PLUGIN_V2 or kPLUGIN_V3 node"
    because the Identity nodes interpose between the INT8 constant and the plugin.
    Removing the Identity nodes and wiring the INT8 initializer directly to each
    plugin node satisfies both TRT's QDQ rule *and* the plugin's INT8 format requirement.
    """
    # Build set of INT8 initializer names
    int8_initializers = {
        init.name
        for init in onnx_model.graph.initializer
        if init.data_type == onnx.TensorProto.INT8
    }
    if not int8_initializers:
        return onnx_model

    # Build a map: Identity output name → resolved source (INT8 initializer name)
    # Handles chains: A(int8) → Identity → Identity → plugin
    identity_map: dict = {}  # identity_output_name -> int8_initializer_name

    def _resolve(name: str):
        return identity_map.get(name, name)

    changed = True
    while changed:
        changed = False
        for node in onnx_model.graph.node:
            if node.op_type != "Identity":
                continue
            src = node.input[0] if node.input else ""
            resolved = _resolve(src)
            if resolved in int8_initializers:
                out = node.output[0]
                if identity_map.get(out) != resolved:
                    identity_map[out] = resolved
                    changed = True

    if not identity_map:
        return onnx_model

    # Rewrite consumer node inputs to use the INT8 initializer directly
    replaced = 0
    for node in onnx_model.graph.node:
        for i, inp in enumerate(node.input):
            if inp in identity_map:
                node.input[i] = identity_map[inp]
                replaced += 1

    # Remove the Identity nodes that are now unused (their output was an alias)
    identity_outputs = set(identity_map.keys())
    kept = [
        n for n in onnx_model.graph.node
        if not (n.op_type == "Identity" and n.output
                and n.output[0] in identity_outputs)
    ]
    removed = len(onnx_model.graph.node) - len(kept)

    if removed or replaced:
        print(
            f"[_elide_int8_identity_nodes] Removed {removed} Identity node(s), "
            f"rewired {replaced} consumer input(s) to INT8 initializer directly."
        )
        del onnx_model.graph.node[:]
        onnx_model.graph.node.extend(kept)

    return onnx_model


def _remove_duplicate_nodes(onnx_model: onnx.ModelProto) -> onnx.ModelProto:
    """Remove exact-duplicate ONNX nodes (same op_type, inputs, and outputs).

    ``fp4qdq_to_2dq`` appends a Cast node for every FP4QDQ node via
    ``_cast_input_dtypes``, naming it ``<activation>_f16``.  When several
    FP4QDQ nodes share the same activation (e.g. weight-tied shared-expert
    norms across MoE layers), identical Cast nodes are appended, leading to
    "Output name is not unique" in TensorRT's ONNX parser.  Removing later
    copies is semantically safe: all consumers already reference the same
    output name, so they transparently use the surviving first node.
    """
    seen: set = set()
    kept = []
    removed = 0
    for node in onnx_model.graph.node:
        key = (node.op_type, tuple(node.input), tuple(node.output))
        if key in seen:
            removed += 1
            continue
        seen.add(key)
        kept.append(node)
    if removed:
        print(
            f"[_remove_duplicate_nodes] Removed {removed} exact-duplicate node(s)."
        )
        del onnx_model.graph.node[:]
        onnx_model.graph.node.extend(kept)
    return onnx_model


def export_onnx(model,
                inputs,
                output_dir,
                input_names,
                output_names,
                dynamic_axes,
                custom_opsets=None):
    '''
    Export the model to ONNX format.
    Args:
        model: The model to export
        inputs: The inputs to the model
        output_dir: The directory to save the ONNX model
        input_names: The names of the input tensors
        output_names: The names of the output tensors
        dynamic_axes: The dynamic axes of the model
        custom_opsets: Optional dict mapping custom domain names to opset versions
    '''
    # Lazy imports: these modelopt symbols may not exist in older environments.
    # Importing here avoids breaking module load when they are unavailable.
    try:
        from modelopt.onnx.llm_export_utils.surgeon_utils import \
            fold_fp8_qdq_to_dq  # noqa: PLC0415
        from modelopt.onnx.quantization.qdq_utils import (  # noqa: PLC0415
            fp4qdq_to_2dq, quantize_weights_to_int4, quantize_weights_to_mxfp8)
    except ImportError:
        fold_fp8_qdq_to_dq = None
        fp4qdq_to_2dq = None
        quantize_weights_to_int4 = None
        quantize_weights_to_mxfp8 = None

    t0 = time.time()
    os.makedirs(output_dir, exist_ok=True)
    onnx_path = f'{output_dir}/model.onnx'
    with torch.inference_mode():
        torch.onnx.export(model,
                          inputs,
                          onnx_path,
                          export_params=True,
                          dynamic_axes=dynamic_axes,
                          input_names=input_names,
                          output_names=output_names,
                          opset_version=ONNX_OPSET_VERSION,
                          do_constant_folding=True,
                          custom_opsets=custom_opsets,
                          dynamo=False)
    t1 = time.time()
    print(f"ONNX export completed in {t1 - t0}s. Apply post-processing...")
    # Post-processing
    onnx.shape_inference.infer_shapes_path(onnx_path)
    onnx_model = onnx.load(onnx_path)
    graph = None

    if is_int4_awq_quantized(model):
        print(
            "INT4 AWQ quantization detected in the model, compressing some weights to INT4 and inserting int4 gemm plugin"
        )
        onnx_model = quantize_weights_to_int4(onnx_model)
        # Fix the Cast nodes and hidden_states output types for INT4 models
        onnx_model = fix_model_int4_output_dtypes(onnx_model)
        graph = gs.import_onnx(onnx_model)
        graph = int4_dq_gemm_to_plugin(graph)
    if is_fp8_quantized(model):
        print(
            "FP8 quantization detected in the model, compressing some weights to FP8"
        )
        if graph is None:
            graph = gs.import_onnx(onnx_model)
        graph = fold_fp8_qdq_to_dq(graph)
    if graph is not None:
        onnx_model = gs.export_onnx(graph)

    # Since torch.onnx.export deduplicates weights, lm_head and embed_tokens can
    # share the same ONNX initializer. To prevent quantization of lm_head (e.g. NVFP4)
    # from affecting embed_tokens, we manually create a separate initializer.
    # See: https://github.com/pytorch/pytorch/blob/v2.9.0-rc9/torch/csrc/jit/passes/onnx/deduplicate_initializers.cpp#L96
    if isinstance(model, EdgeLLMModelForCausalLM) and is_fp4_quantized(
            model.lm_head):
        onnx_model = untie_nvfp4_lm_head_initializer(onnx_model)
    if is_fp4_quantized(model) or any(n.op_type == "TRT_FP4QDQ"
                                      for n in onnx_model.graph.node):
        print(
            "NVFP4 quantization detected in the model, compressing some weights to NVFP4"
        )
        onnx_model = fp4qdq_to_2dq(onnx_model)
        # fp4qdq_to_2dq._cast_input_dtypes appends a Cast node per FP4QDQ node
        # using ``input_name + "_f16"`` as the output name.  When multiple FP4QDQ
        # nodes share the same activation input (e.g. weight-tied shared-expert
        # norms), multiple identical Cast nodes are created, causing
        # "Output name is not unique" in TRT's ONNX parser.
        # Fix: drop exact-duplicate nodes (same op_type + inputs + outputs).
        onnx_model = _remove_duplicate_nodes(onnx_model)
        # torch.onnx.export deduplicates identical INT8 buffers (e.g. hidden_block_scale
        # placeholders) into one initializer and fans them out via Identity nodes.
        # TRT's QDQ optimizer rejects INT8 constants not directly before DQ/plugin nodes.
        # Fix: short-circuit Identity pass-throughs so INT8 initializers reach
        # plugin nodes directly (which IS allowed by TRT's QDQ rule).
        onnx_model = _elide_int8_identity_nodes(onnx_model)
    if is_mxfp8_quantized(model):
        print(
            "MXFP8 quantization detected in the model, compressing some weights to MXFP8"
        )
        onnx_model = quantize_weights_to_mxfp8(onnx_model)

    print(
        "Removing all the files in the output directory except for .json files"
    )
    for file in os.listdir(output_dir):
        if file.endswith(".json"):
            continue
        os.remove(os.path.join(output_dir, file))

    # Save the model to the output directory
    onnx.save_model(onnx_model,
                    onnx_path,
                    save_as_external_data=True,
                    all_tensors_to_one_file=True,
                    location="onnx_model.data",
                    convert_attribute=True)
    t2 = time.time()
    print(
        f"ONNX post-processing completed in {t2 - t1}s. ONNX file is saved to {output_dir} in {t2 - t0}s."
    )


def export_onnx_dynamo(model,
                       inputs,
                       output_dir,
                       input_names=None,
                       output_names=None,
                       input_dynamic_shapes=None,
                       output_dynamic_shapes=None,
                       opset_version=None):
    '''
    Export the model to ONNX format using dynamo.
    Args:
        model: The model to export
        inputs: The inputs to the model
        output_dir: The directory to save the ONNX model
        input_names: The names of the input tensors
        output_names: The names of the output tensors
        input_dynamic_shapes: The dynamic shapes of the input tensors
        output_dynamic_shapes: The dynamic shapes of the output tensors, tuple of dicts mapping dim index to name
        opset_version: ONNX opset version to use (default: ONNX_OPSET_VERSION from common.py)
    '''
    if opset_version is None:
        opset_version = ONNX_OPSET_VERSION

    t0 = time.time()
    os.makedirs(output_dir, exist_ok=True)
    onnx_path = f'{output_dir}/model.onnx'
    with torch.inference_mode():
        exported_model = torch.onnx.export(model,
                                           inputs,
                                           onnx_path,
                                           dynamic_shapes=input_dynamic_shapes,
                                           input_names=input_names,
                                           output_names=output_names,
                                           opset_version=opset_version,
                                           dynamo=True)

    # Modify output dimensions according to output_dynamic_shapes as the dynamo exporter
    # does not expose this option.
    if output_dynamic_shapes is not None:
        outputs = exported_model.model.graph.outputs
        for output_idx, dynamic_shape_dict in enumerate(output_dynamic_shapes):
            if output_idx >= len(outputs):
                raise ValueError(f"Output {output_idx} not found in the model")
            output = outputs[output_idx]
            for dim_idx, dim_name in dynamic_shape_dict.items():
                if dim_idx < len(output.shape):
                    # Set the dimension to a symbolic name
                    output.shape[dim_idx] = dim_name
                else:
                    raise ValueError(
                        f"Dimension {dim_idx} not found in output {output_idx}"
                    )

    # Save the modified model
    exported_model.save(onnx_path)

    t1 = time.time()
    print(f"ONNX export completed in {t1 - t0}s. Apply post-processing...")
