#!/usr/bin/env python3
# ===- import-embeddinggemma.py - embeddinggemma AOT importer ------------===//
# EmbeddingGemma AOT importer for Buddy-MLIR.
# Implements the SentenceTransformer pipeline using the buddy-codegen
# single_forward interface.: `--spec` + `--output-dir`, with
# subgraph0.mlir / forward.mlir / arg0.data written at the output-dir ROOT.
#
# Architecture (unchanged from the original PR):
#   Gemma3TextModel -> Mean Pooling -> Dense(768->3072) ->
#   Dense(3072->768) -> L2 Normalize -> 768-dim embedding
#
# Model source resolution (in order):
#   $EMBEDDINGGEMMA_MODEL_PATH  (set by buddy_add_model LOCAL_MODEL_ENV)
#   $BUDDY_LOCAL_MODEL_PATH     (generic fallback)
#   spec["hf_model_path"]       (e.g. google/embeddinggemma-300m)
#
# ===----------------------------------------------------------------------===//
import argparse
import json
import os

import numpy
import torch
import torch.nn as nn
from buddy.compiler.frontend import DynamoCompiler
from buddy.compiler.graph import GraphDriver
from buddy.compiler.graph.operation import *  # noqa: F403
from buddy.compiler.graph.transform import simply_fuse
from buddy.compiler.graph.type import DeviceType
from buddy.compiler.ops import tosa
from sentence_transformers import SentenceTransformer
from torch._inductor.decomposition import decompositions as inductor_decomp


# ==============================================================================
# The wrapper executes the SentenceTransformer pipeline as a single
# forward graph. It takes (input_ids, attention_mask) and returns the
# normalized sentence embedding.
# ==============================================================================
class EmbeddingGemmaWrapper(nn.Module):
    def __init__(self, model_path):
        super().__init__()
        st_model = SentenceTransformer(model_path, device="cpu")
        st_model.eval()

        # Extract sub-modules
        self.transformer = st_model._first_module()
        self.pooling = st_model._modules["1"]
        self.dense1 = st_model._modules["2"]
        self.dense2 = st_model._modules["3"]
        self.normalize = st_model._modules["4"]

        # Force float32
        for p in self.parameters():
            p.data = p.data.float()

        # Single forward pass only: disable KV cache so Dynamo does not
        # materialize past-key/value tensors in the compiled graph.
        try:
            auto_model = getattr(self.transformer, "auto_model", None)
            if auto_model is not None:
                auto_model.config.use_cache = False
        except Exception:  # noqa: BLE001 - best-effort
            pass

    def forward(self, input_ids: torch.Tensor, attention_mask: torch.Tensor):
        # 1. Transformer (Gemma3TextModel)
        auto_model = self.transformer.auto_model
        if input_ids.shape[1] > auto_model.config.sliding_window:
            raise ValueError("Input length exceeds the bidirectional window")
        # Embed IDs first to preserve the runner's (IDs, mask) input order.
        inputs_embeds = auto_model.embed_tokens(input_ids)
        # Within one bidirectional window, both layer types use this mask.
        additive_mask = (
            1.0 - attention_mask[:, None, None, :].float()
        ) * torch.finfo(inputs_embeds.dtype).min
        additive_mask = additive_mask.expand(
            -1, 1, input_ids.shape[1], -1
        ).contiguous()
        trans_out = self.transformer(
            {
                "inputs_embeds": inputs_embeds,
                "attention_mask": {
                    "full_attention": additive_mask,
                    "sliding_attention": additive_mask,
                },
            }
        )
        token_emb = trans_out["token_embeddings"]

        # 2. Mean Pooling (traceable: all tensor ops, no control flow)
        mask_expanded = (
            attention_mask.unsqueeze(-1).expand(token_emb.size()).float()
        )
        sum_emb = torch.sum(token_emb * mask_expanded, dim=1)
        sum_mask = mask_expanded.sum(dim=1).clamp(min=1e-9)
        pooled = sum_emb / sum_mask

        # 3. Dense 768 -> 3072 (Linear + Identity activation)
        pooled = {"sentence_embedding": pooled}
        d1_out = self.dense1(pooled)["sentence_embedding"]

        # 4. Dense 3072 -> 768 (Linear + Identity activation)
        d2_out = self.dense2({"sentence_embedding": d1_out})[
            "sentence_embedding"
        ]

        # 5. L2 Normalize
        normed = self.normalize({"sentence_embedding": d2_out})[
            "sentence_embedding"
        ]

        return normed


# ==============================================================================
# 1. Argument parsing
# ==============================================================================
p = argparse.ArgumentParser(description="embeddinggemma-300m AOT importer")
p.add_argument("--spec", required=True, help="Variant spec JSON")
p.add_argument("--output-dir", required=True, help="Directory to save outputs")
a = p.parse_args()

with open(a.spec) as f:
    spec = json.load(f)

model_path = (
    os.environ.get("EMBEDDINGGEMMA_MODEL_PATH")
    or os.environ.get("BUDDY_LOCAL_MODEL_PATH")
    or spec.get("hf_model_path", "google/embeddinggemma-300m")
)
max_seq_len = int(spec.get("max_seq_len", 128))
os.makedirs(a.output_dir, exist_ok=True)

# ==============================================================================
# 2. Load model
# ==============================================================================
print("[import-embeddinggemma] Loading embeddinggemma-300m from:", model_path)
model = EmbeddingGemmaWrapper(model_path)
model.eval()
total_params = sum(p.numel() for p in model.parameters())
print(f"   Total parameters: {total_params:,} ({total_params / 1e6:.1f}M)")

# ==============================================================================
# 3. Initialize Dynamo Compiler
# ==============================================================================
dc = DynamoCompiler(
    primary_registry=tosa.ops_registry,
    aot_autograd_decomposition=inductor_decomp,
    func_name="forward",
)

# ==============================================================================
# 4. Dummy inputs (fixed shape; matches the original PR)
# ==============================================================================
dummy_input_ids = torch.ones((1, max_seq_len), dtype=torch.int64)
dummy_attention_mask = torch.ones((1, max_seq_len), dtype=torch.int64)
print("[import-embeddinggemma] Dummy inputs:")
print(f"   input_ids:      {tuple(dummy_input_ids.shape)}")
print(f"   attention_mask: {tuple(dummy_attention_mask.shape)}")

# ==============================================================================
# 5. Trace the model
# ==============================================================================
print("\n[import-embeddinggemma] Tracing forward graph...")

with torch.no_grad():
    graphs = dc.importer(
        model,
        input_ids=dummy_input_ids,
        attention_mask=dummy_attention_mask,
    )

assert len(graphs) == 1, f"Expected 1 graph, got {len(graphs)}"


graph = graphs[0]
params = dc.imported_params[graph]
print(
    f"[import-embeddinggemma] {len(graphs)} graph(s), "
    f"{len(params)} params, "
    f"{sum(p.numel() for p in params):,} elems"
)

# ==============================================================================
# 6. Graph optimization (simply_fuse ONLY)
# ==============================================================================
graph.fuse_ops([simply_fuse])
graph.op_groups["subgraph0"] = graph.op_groups.pop("subgraph0")
graph.group_map_device["subgraph0"] = DeviceType.CPU

driver = GraphDriver(graph)
driver.subgraphs[0].lower_to_top_level_ir()

# ==============================================================================
# 7. Save outputs at the output-dir ROOT (single_forward build convention)
# ==============================================================================
with open(os.path.join(a.output_dir, "subgraph0.mlir"), "w") as module_file:
    print(driver.subgraphs[0]._imported_module, file=module_file)
with open(os.path.join(a.output_dir, "forward.mlir"), "w") as module_file:
    print(driver.construct_main_graph(True), file=module_file)

all_param = numpy.concatenate(
    [param.detach().cpu().numpy().reshape([-1]) for param in params]
).astype(numpy.float32, copy=False)
all_param.tofile(os.path.join(a.output_dir, "arg0.data"))

print(
    f"[import-embeddinggemma] Wrote forward.mlir, subgraph0.mlir, "
    f"arg0.data ({all_param.size} f32 elems) to {a.output_dir}"
)
