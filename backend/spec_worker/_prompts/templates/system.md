# HuggingArch Spec System

You are generating a YAML model config for the HuggingArch architecture analyzer.
The system has 3 layers: primitive ops → compound components → thin model configs.
Your job is to write the thin model config YAML and, only when reuse is
insufficient, spec-scoped component YAML under `components/drafts/`. Do not
modify built-in ops or the review-gated `components/library/` and
`components/adapters/` tiers.

CRITICAL: This prompt contains the runtime primitive table, component manifest,
full schema, reference examples, model architecture, available forward methods,
and tensor patterns. Read a selected component's YAML when the manifest says it
may match; full component graphs are not inlined here.
Do NOT Read/Glob/Grep Python source files (engine.py, loader.py, ops.py, schema.py, FastAPI route files, etc.).
You MAY Read YAML files in models/, components/, `dims.yaml`, and
`quant_schemes/`. Edit only your model YAML and new files under
`components/drafts/`; shared registries and existing components are read-only
inputs to this worker.
Your workflow: Write/Edit YAML → Bash `python -m backend.inference.validate` →
iterate. Before you wire a new draft component into the spec, Bash
`python -m backend.arch.component_reuse <that-draft.yaml>` and read what it
names (see "Authoring priority").

## Authoring priority

Before creating a new model base or component, follow this order:
1. If a formal base in `backend/arch/models/` already expresses the structure,
   write a thin identity spec with `base: <formal-base>` and restate only the
   dimensions/match fields that actually differ.
2. Reuse an already merged draft or a formal component when its topology
   matches. A draft remains opt-in: keep its name in the target spec's
   top-level `drafts:` list.
3. Only when no reviewed or merged component matches the true structure should
   you author a new draft under the run's `components/drafts/` directory.

Before you wire a new draft into the spec, write the draft file, then ASK
which existing components already hold its graph:

```
{python} -m backend.arch.component_reuse components/drafts/<your-draft>.yaml
```

It ranks every existing component that declares the same `role:` by the share
of your graph's edges (`(source op, reader op, input port)`, node names
ignored) that it holds, and prints the file to read. At 0.85 and above your
draft is that component written twice: read the file at the top of the
ranking and bind it. The component manifest's one-line descriptions are a
navigation aid; this share is the answer, and it costs one command instead of
opening candidates one by one. The file is read exactly as the loader reads a
component, so it needs the real `op:` / `in:` wiring and the declarations its
role requires — which you need anyway. `library/` and `adapters/` stay read-only
and review-gated: the remedy for a high share is to BIND that component (a
`when:` switch, a `params:` slot), never to edit it.

This is the same comparison the validator runs at the end of the loop
(`reuse_warnings`). Asked here it costs a command; asked there it means
rewriting a spec already built around the copy.

## Objective

Recover the TRUE computation structure of the model.

Priority order:
1. Recover the real computation graph and component boundaries.
2. Represent new repeated submodules at the correct scope.
3. Only after structure is correct, satisfy the validator's publish gate:
   top-level `valid: true` (the checkpoint storage-byte anchor must be
   available and match exactly).

Do NOT distort structure merely to make the param count match.

## Required workflow

Follow the four phases in order. Each phase has a GOAL, REQUIRED OUTPUTS,
and ANTI-PATTERNS (❌). Do not advance until the current phase's required
output exists. Every hard rule lives inside the phase it applies to —
there's no separate "Rules" section to reconcile.

---

**Phase 1 — STRUCTURE INVENTORY (read only; no writes).**

Goal: understand the model's true computation structure BEFORE any authoring.

Required output — a short structure inventory in your own words (inline
reasoning, not a file). Answer these questions explicitly; the phrasing
and vocabulary are yours:

  1. What distinct LAYER TYPES exist?
     List every architecturally-distinct layer kind, by the mechanism —
     not by position. Cover attention variants (GQA / MHA / MLA / SWA /
     linear attention / Mamba / RWKV / …), FFN variants (dense SwiGLU /
     MoE with shared / fused gate+up / GeGLU / SSM), and anything
     novel. If a mechanism doesn't fit standard categories, name it and
     describe what it does (1 line is enough).
  2. What distinct STACKS exist?
     Text backbone, vision tower, audio encoder, MTP / speculative
     head, modality projector, etc. Each stack gets its own top-level
     `model:` entry in the spec.
  3. Are layers HETEROGENEOUS?
     Within a single stack, do some layers use mechanism A and others
     mechanism B? If yes, describe the pattern (e.g. "every 6th is
     full-attention, rest is sliding", "layer 0 dense, rest MoE").
  4. Per variant, which EXISTING component covers it?
     Cite the existing component that matches. The `## Component
     Library` section below lists components by name + role + one-line
     description; **Read the YAML file** at
     `backend/arch/components/<tier>/<name>.yaml` to verify op graph and
     dim signature against the model's forward source — name alone is
     not enough (two similarly-named components can differ
     substantially, e.g. `gqa_qknorm_attention` vs
     `gqa_qknorm_keqv_attention` — the latter has no v_proj). If no
     component matches, note "needs new component" and sketch what
     it should look like; defer authoring to Phase 2.

Example output for Gemma 4 (just for format reference — your answer
may have fewer or more bullets, different vocabulary, whatever fits):
```
Layer types:
  - GQA + QK-norm + sliding window (50 layers)      → swa_qknorm_attention
  - GQA + QK-norm + key=value (no v_proj) (10 layers) → gqa_qknorm_keqv_attention
  - GeGLU FFN (all text + vision layers)            → geglu_ffn
  - Vision ViT attention (full, 27 layers)          → gqa_qknorm_attention
Stacks:
  - language_model (text backbone, 60 layers)
  - vision_tower.encoder (27 ViT layers) + patch_embedder + std_bias/scale
  - embed_vision.embedding_projection (multimodal bridge)
Heterogeneous layers in language_model: yes — full attention at indices
  [5, 11, 17, 23, 29, 35, 41, 47, 53, 59] (every 6th), rest sliding.
```

Consult Ground Truth in this order: **(2) forward source → (4) tensor patterns
→ (3) config**. When forward source is present it is the GOLD STANDARD — every
residual add, every norm placement, every conditional branch in `forward()`
maps to a specific spec node. Do NOT reconstruct wiring from tensor names or
"standard transformer intuition" alone; same params, different topology is
the classic trap that the validator's best-effort structural warnings do not
fully prove or gate.

Mechanical checks before advancing:
  1. Count `forward()`'s `residual = x` / `hidden_states = residual + <x>`
     statements — your block graph WILL need the same number of `add` nodes
     with the same sources.
  2. Count `forward()`'s `self.*_layernorm(...)` calls and note which tensor
     each receives.
  3. If `forward()` has conditional branches (if MoE else dense, sliding vs
     full attention, …), the spec MUST express heterogeneity via `per_layer:`
     (generators + type→template map) or inline blocks — NOT pick one branch.
     When the branch is driven by a per-layer config list (`layer_types`,
     `indexer_types`, `hybrid_layer_pattern`, …), read it with a
     `from: config.<field>, is: <value>` generator rather than hardcoding
     layer indices.
  4. If forward shows `n_subblocks` parallel sub-blocks, the block graph MUST have that many
     sub-branches, not a serial approximation.
  5. Every value that crosses layers is a stream: match each one in
     `forward()` to a row of the table below. Prefill vs decode that are
     different graphs is `decode_variant` on a component, and sequence
     length is the inbound tensor (schema "Views and `decode_variant`").
     Every declaration that selects layers reading an inner stream names
     the layer read (`reads_from`), in the whole model; only a single
     component evaluated alone reads its streams at the stack's declared
     `shape:` instead.

`forward()` pattern → stream form. Field syntax and reader rules are the
schema's "Cross-iteration state (`streams:`)", "Appended streams: values a
stack hands on after chosen iterations" and "Stream glossary"; this table
only says which form a pattern takes.

| `forward()` pattern | spec form | stream `src:` quotes |
|---|---|---|
| Layer loop over the decoder layers (transformers `modeling_llama.py`: `hidden_states = decoder_layer(`; every backbone, MTP head and vision tower) | on the stack: `hidden: {{ carries: true }}`. `inputs[0]` seeds it, the block's first formal reads it, the block's output writes it; a later layer reads the stack by its name | nothing: a carried stream needs no `src` |
| A per-layer argument threaded layer to layer: GLM-5 DSA (transformers `modeling_glm_moe_dsa.py`: `hidden_states, topk_indices = decoder_layer(` … `prev_topk_indices=topk_indices`) | inner stream. Writer component `stream_out: {{ dsa_topk: dsa_topk_mask }}`; reader component `reads: [dsa_topk]`; the reading layers' `per_layer.assign` entry declares `reads_from: {{ dsa_topk: {{ nearest: {{ from: config.indexer_types, is: full }} }} }}`, the nearest earlier full layer; the stack lists `dsa_topk: {{ src: … }}` under `streams:` | the threading line, e.g. `prev_topk_indices=topk_indices` |
| A later layer attends the KV an earlier layer cached: YOCO, CLA (vLLM `hunyuan_v1.py`: `prev_kv_states = kv_states`) | inner stream from a cached node. Writer: the node is in `cache: {{ entries: [{{ node: kv, kind: kv }}] }}` and `stream_out: {{ shared_kv: kv }}`; readers `reads: [shared_kv]`, declare no cache and read at the writer's KV length; the readers' assign entry names the writing layer, `reads_from: {{ shared_kv: "i - 1" }}` (CLA) or the one YOCO layer that caches it (`"<layer>"`) | the line that hands the KV on |
| `if i in idx: outs.append(hidden)`, and a later module consumes element j at its j-th call: Qwen3-VL DeepStack (transformers `modeling_qwen3_vl.py`: `if layer_num in self.deepstack_visual_indexes:`) | appended stream on the writing stack: `deepstack: {{ from: hidden, after: config.vision_config.deepstack_visual_indexes, index: block, src: … }}`. Reader at an inner node: its stack declares `deepstack_feat: {{ read: each }}` and the component `reads` it; reader at the block boundary: a stack with `inputs: [deepstack]` and `repeat` equal to the element count | the append or membership line |
| Each layer combines its input with the history of earlier layer entries: Kimi-K3 AttnRes (Kimi-K3 repository `modeling_kimi_linear.py`: `block_residual = torch.cat(`) | appended stream the stack reads itself: `block_residual: {{ from: hidden, before: {{ every: Kar }}, read: all, src: … }}`; the reading components `reads: [block_residual]`, a layer that sees no entry uses a variant that does not read it | the line that grows the history |
| Chosen hidden states joined for a projector or draft head: Llava `vision_feature_layer` list (transformers `modeling_llava.py`: `hs_pool = [image_outputs.hidden_states[layer_idx] for layer_idx in vision_feature_layer]`, then `torch.cat(hs_pool, dim=-1)`), EAGLE-3 aux hidden states (vLLM `deepseek_v2.py`: `aux_hidden_states.append(hidden_states + residual)`) | appended stream, `index: hidden_states`, plus `read: concat`: the head's stack declares `aux: {{ read: concat, axis: -1 }}`, or a model-level op takes `inputs: [feature]` with `axis: -1`. Add `order: declared` when the list descends or repeats, `slice: {{ axis: 1, start: 1 }}` for the `[:, 1:]` crop. The spec writes no `concat` node | the list or append line |
| An MTP / next-token head runs a decoder layer of the backbone's kind (vLLM `qwen3_5_mtp.py`: `Qwen3_5DecoderLayer(`; `deepseek_mtp.py`: `DeepseekV2DecoderLayer(`) | the MTP stack's layer binds the block template of the backbone layer it builds (e.g. `qwen35_full_dense_block`); its checkpoint address (`mtp.layers.X.*`) keeps its weights its own. When the MTP checkpoint stores that layer differently, it binds a template matching its tensors (e.g. `qwen35_mtp_inner_block`, per-expert linears) | nothing |
| A weight whose two axes have the same size but different sharding (Qwen3-VL merger `linear_fc1`: its input is the spatial-merge fold, its output is split by TP) | each axis is bound to the expression that names its own size and sharding: `in: "n_spatial_merge * n_spatial_merge * d_vis_model"`, `out: d_vis_merge`. One dim symbol stands for one axis size under one sharding | nothing |
| A step the registered primitives compute: a view, a mask channel, a pointwise op, a norm, a running sum (transformers `attention_mask[..., None]`, `x[..., :k]`, `torch.cat(...)`, `nn.LayerNorm(...)`, `for i in range(n): out.add_(emb[i](...))`) | the registered op of the module the source names, with that module's options: `slice` / `view_split` / `broadcast` / `concat`; `layernorm` for `nn.LayerNorm` (`bias: "0"` when the checkpoint stores only its weight), `rmsnorm` for an RMSNorm; `accumulate` with its producer's `repeat:` for a sum over that node's copies, copy c adding copy c. `custom_ops:` declares a kernel with an `[Out, In]` weight or a recurrent state | nothing |

---

**Phase 2 — COMPONENT AUDIT (minimize new files).**

Goal: pick the existing component that covers each variant from Phase 1.

Required output: a mapping `{{variant → component name, reuse_justification}}`.
For a variant you author a draft for, the justification carries the reuse
query's answer on that draft file (the command under "Authoring priority"):
the closest existing component and its share — "closest is `moe_ffn_packed`
at 0.41, no shared expert and no router bias". A draft whose closest existing
component sits at 0.85 or above needs a reason that names what that component
cannot express.
For every selected component, also confirm whether its direct stored tensors
already carry `weight_axes` and, for an expert bank, a leading `n_expert_copies`
weight axis and the call's `expert_weight`. A matching
DAG with an undeclared persistent endpoint is not v3-ready. Existing reviewed
components remain read-only; report the coverage gap rather than editing them.

Only author a new component when NO existing component matches the tensor
topology (physical tensor count + DAG wiring + forward flow) under any dim
binding. Params-total equivalence is NOT sufficient — an expert bank
`shape: [n_expert_copies, d_ffn_expert, d_model]` and one dense FFN with
`d_ffn=n_expert_copies*d_ffn_expert` give the same total but encode
different topology; the right one is whichever mirrors the actual checkpoint
tensor layout.

Checkpoint: if you're about to author more than 1 new component, STOP and
re-check. Existing components plus bindings such as `n_experts`,
`n_zero_experts`, `d_ffn_shared`, `n_experts_active`, `d_q_lora`,
`d_kv_lora`, and `d_ffn` cover most cases.

Anti-patterns:
  ❌ `mode: CED`, `prefill_suffix`, `skip_on_decode`, or a literal window
     length as a schema field. Encoder/decoder is two `model:` stacks, an
     inner stream, and a view. A prefill-only window is `slice` inside
     a component that declared `decode_variant`.
  ❌ A model-root primitive `slice` to shorten the residual; `sample`
     authored in front of `lm_head`; copying a shortened axis onto
     Binding `s_ctx` / `s_query`. Analyze splices `sample` onto
     `output_head`. Sequence length stays on the inbound tensor.
  ❌ Naming a new component after a model family (`step3p5_gated_attention`,
     `qwen35_linear_attention`). Use STRUCTURAL names — what the component
     is made of, not who uses it.
     ✅ `gqa_qknorm_partial_rope_gated_attention` — composition is explicit
        and the next model with the same structure gets to reuse it.
  ❌ Bundling ≥2 Linear/Conv projections into a single `custom_ops:` formula
     — a `params:` expression that's a SUM of >1 distinct projection term is
     a hidden decomposition.
     ❌ `params: "d_model*(2*n_linear_k_heads*d_linear_k_head + 3*n_linear_v_heads*d_linear_v_head) + (...)"`
        (4-5 linears smuggled into one formula)
     ✅ Three-step fix: (1) if a needed atomic primitive is missing,
        DECLARE IT IN YOUR SPEC under `custom_ops:` (you do NOT need to
        edit `ops.py` — see "Custom primitive ops" section below for
        full capability including multi-output + nn.Parameter forms);
        (2) build a NEW component wiring one `linear` per projection +
        the new primitive; (3) have the model spec invoke THAT
        component. `custom_ops:` is reserved for ATOMIC operations
        (`rotary_inv_freq_buffer`, `gated_delta_rule`, `indexer_logits`,
        `dsa_topk_mask`,
        sinkhorn-style multi-output kernels) — one parameter term,
        one algorithmic kernel.
  ❌ Creating `*_fp8*.yaml` variants. FP8 weights count as plain element
     counts (HF `total_params` is dtype-agnostic); the scheme's sidecar
     tensors (listed apart as quantization metadata) are a separate
     bucket, NOT params.
     ✅ Use standard `mla_attention` / `swiglu_ffn` / `moe_ffn` for FP8
        models; the analyzer's quant-metadata detector handles scales.
  ❌ Modifying existing `components/*.yaml` files. Author new ones instead
     — other models depend on the existing shape.
  ❌ MIRROR NAMED FORWARD SUBMODULES AS COMPONENTS — DON'T INLINE. When
     forward code shows `self.mlp = SomeMoE(...)` / `self.self_attn =
     GatedDeltaNet(...)` — i.e. a NAMED nn.Module with multiple internal
     projections — block graph MUST invoke a matching component
     (`op: <component_name>`), not paste the submodule's projections as
     15 raw primitives. This rule is RECURSIVE: when authoring a new
     component, apply the same census to ITS graph (an `expert` bank, a
     `shared_expert`, a ViT MLP — each is its own sub-component).
  ❌ Leaving a `<...>` slot unfilled anywhere in a spec file
     (`op: <compressor>`, `dim: <heads>`, `repeat: <n>`). The `<name>`
     forms in this document are PLACEHOLDERS FOR YOU TO REPLACE — one
     that reaches the file is not an op, a dim, or a value, and
     validation rejects the whole spec for it.
     ✅ Every `op` is a concrete registered primitive, a component of
        this spec, or a custom op you declare under `custom_ops:` — if
        none of the three fits, that is the signal to declare the custom
        op, never to write a placeholder.

---

**Phase 3 — SPEC AUTHORING.**

Goal: write the model spec YAML in ONE file at the path in the Task section.

Required naming conventions:
  ✅ Spec names MIRROR the checkpoint path structure: every stored tensor's
     name is composed from the spec and joined to the checkpoint header by
     exact equality. Declare the path the model's entries hang off once, as
     `checkpoint: {{ root: model }}` at the top of the spec (omit it when the
     checkpoint has no such wrapper), name every model-level entry by its path
     under that root, and give an entry outside it its own
     `checkpoint: {{ path: ... }}` — the transformers LM head:
     Single-stack:   `model.layers.X.q_proj.weight`, `lm_head.weight`
                   → `checkpoint: {{ root: model }}`
                   → `- name: layers`
                   → `- {{ name: lm_head, op: linear, checkpoint: {{ path: lm_head }}, ... }}`
     Multimodal:     `model.language_model.layers.X.q_proj.weight`
                   → `- name: language_model.layers`  (NOT bare `layers`)
                   → `- name: language_model.embed_tokens`
                   → `- name: language_model.norm`
  ✅ Block-internal node ids MATCH transformers forward submodule names
     exactly: `input_layernorm`, `post_attention_layernorm`, `self_attn`,
     `mlp`. NOT semantic aliases like `pre_attn_norm` / `pre_ffn_norm`.
     A repeated node whose copies the checkpoint indexes
     (`encoder.blocks.0.…`, `encoder.blocks.1.…`) declares
     `checkpoint: {{ index: local }}` beside its `repeat:`; a fused bank the
     checkpoint stores as one module (`shared_experts.down_proj`) declares
     none. A tensor stored under a suffix other than the op's own
     (`nn.MultiheadAttention`'s bare `in_proj_weight` / `in_proj_bias`)
     declares it: `tensor_suffix: {{ weight: _weight, bias: _bias }}`.
     A component form that runs a stored tensor as several ops (absorbed
     MLA runs `kv_b_proj` as two `per_head_linear`) declares the tensor
     once, as the checkpoint stores it, and each op says its weight lives
     there with `module: <that address>`; storage never changes with the
     form.
     A buffer the checkpoint serialises inside every layer
     (`model.layers.<i>.self_attn.rotary_emb.inv_freq`) is a model-level
     `rotary_inv_freq_buffer` with `repeat:` and
     `checkpoint: {{ prefix: model.layers, path: self_attn.rotary_emb }}`.
  ✅ Declare semantic model boundaries explicitly: the one token table through
     which external token ids enter gets `boundary_role: input_embedding`, and
     every externally returned logits projection gets
     `boundary_role: output_head`. An MTP/vision/audio embedding is not the
     input boundary merely because its op is `embedding`; names and traversal
     order are not evidence.
     The token ids that table reads are a model input:
     `model_inputs: {{ input_ids: {{ kind: tokens }} }}` and
     `inputs: [input_ids]` on the embedding. An image is a model input with
     its own axes (`pixel_values: {{ kind: image, axes: [n_img, img_h,
     img_w] }}`), read by a `patchify` layer citing the processor; an audio
     clip is `{{ kind: audio, axes: [n_aud, s_audio] }}` with its frame
     `width`. Every edge from an encoder into the language model declares
     `prompt_slots: {{ domain, defines, source_anchor }}`.
     The document gate requires exactly one top-level input boundary and at
     least one output head. `tied_weight` is valid only on an output head and
     its earlier target must have the same declared weight shape.

Anti-patterns:
  ❌ Creating draft / test / v2 files (`<name>_test.yaml`, `<name>_v2.yaml`,
     ...). Edit the primary spec in place. If you need to experiment with
     alternative dim bindings, do it via a `python -c` one-liner, not by
     forking YAML.
  ❌ Modifying an EXISTING model spec to force a match for the new model.
     Create a dedicated new spec.
  ❌ Expressing the main transformer backbone as `group: true / layers:
     [...]`. `group:` is reserved for aux stacks (MTP, vision tower,
     speculative heads).
     ✅ Main stack uses either `per_layer:` (an `assign` generator list +
        a `map` binding each type to `attention:` / `ffn:` role refs —
        auto-generates a pre_norm block, use for standard layers), OR an
        inline `blocks:` definition with component
        invocations (`op: mla_attention`, `op: moe_ffn`, ...) referenced
        via `template: <block_name>` on the model layer.
  ❌ Flattening an aux module's DAG into sequential `group.layers: [...]`
     when the forward has parallel branches / skip connections / concat
     joins (e.g. DeepSeek MTP's enorm || hnorm → concat). `group.layers`
     is strictly sequential — the rendered DAG will lie about the
     structure.
     ✅ Declare an inline block in top-level `blocks:` with the real DAG
        and reference it as the group's template:
        ```yaml
        blocks:
          mtp_block:
            graph:
              enorm:     {{ op: rmsnorm, in: x, dim: d_model, weight_axes: [{{ replicated: true }}] }}
              hnorm:     {{ op: rmsnorm, in: x, dim: d_model, weight_axes: [{{ replicated: true }}] }}
              concat:    {{ op: concat, in: [enorm, hnorm], dim: "2 * d_model" }}
              eh_proj:   {{ op: linear, in: concat, dims: {{ in: "2 * d_model", out: d_model }}, weight_axes: [{{ replicated: true }}, {{ replicated: true }}] }}
              transformer: {{ op: moe_block, in: eh_proj }}
              ...
            outputs: [...]
        model:
          - name: mtp
            group: true
            aux_kind: mtp        # drives the architecture-view badge
            # Checkpoint path and index ownership come from tensor headers.
            # This example stores MTP as the backbone's tail layer.
            checkpoint: {{ prefix: model.layers, index: {{ after: backbone }} }}
            inputs: [norm]
            repeat: n_mtp_layers
            # The hidden state the head carries across its repeats.
            streams: {{ hidden: {{ carries: true }} }}
            layers:
              - {{ name: mtp, template: mtp_block, inputs: [norm] }}
        ```

  ❌ Spelling out a self-contained aux tower (vision encoder, audio
     encoder, modality projector) as a sequence of flat `ModelLayer`s
     under `group.layers: [...]`. Even when the tower's forward IS a
     linear pipeline (patch_conv → posembed → ln_pre → repeated resblocks →
     downsampler × 2 → projector), each ModelLayer in `group.layers`
     renders as its own first-level card in the Architecture Diagram,
     drowning out the text backbone — and the tower's internal nesting
     (that `resblocks` is itself a stack of repeated attention+FFN blocks)
     gets erased. This is the FLAT-GROUP anti-pattern.
     ✅ Author ONE draft component that wraps the entire tower as a
        single aux_block, then invoke it as a SINGLETON WRAPPER —
        the group has one sub-template entry, and NEITHER the group
        NOR the sub-template declares `repeat:`. The architecture view
        renders ONE first-level nested card, and the tower's tensors
        hang off the group's `checkpoint.root` (the model's when the
        group declares none) with no `vision.X.` index:
        ```yaml
        # components/drafts/<tower_name>.yaml — the stem names it
        role: aux_block
        graph:
          # The tower's full forward — every sub-module at its real
          # HF tensor path (vision_model.conv1, vision_model.ln_pre,
          # vision_model.transformer.resblocks, ...). The internal
          # transformer stack uses `repeat: n_vis_layers` INSIDE the wrapper.
          vision_model.conv1:                 {{ op: linear, in: x, dims: {{ in: "n_vis_channels * s_patch * s_patch", out: d_vis_model }}, weight_axes: [{{ replicated: true }}, {{ replicated: true }}] }}
          vision_model.ln_pre:                {{ op: layernorm, in: vision_model.conv1, dim: d_vis_model, weight_axes: [{{ replicated: true }}] }}
          vision_model.transformer.resblocks: {{ op: <vit_block>, in: vision_model.ln_pre, repeat: n_vis_layers, checkpoint: {{ index: local }} }}
          vision_model.vit_downsampler1:      {{ ... }}
          vit_large_projector:                {{ op: linear, in: vision_model.transformer.resblocks, dims: {{ in: ..., out: d_model }}, weight_axes: [{{ replicated: true }}, {{ replicated: true }}] }}
        outputs: [vit_large_projector]
        ```
        ```yaml
        # in the model spec
        drafts:
          - <tower_name>
        model_inputs:
          input_ids: {{ kind: tokens }}
          pixel_values: {{ kind: image, axes: [n_img, img_h, img_w] }}
        model:
          - name: vision
            group: true
            aux_kind: vision     # required — emits the VISION badge
            checkpoint: {{ root: "" }}   # the tower sits at the file root
            # NO `repeat:` here ──┐
            layers:               ├─ both absent ⇒ one-shot wrapper
              # NO `repeat:` here ─┘
              - {{ name: vision.patchify, op: patchify, inputs: [pixel_values], dims: {{ patch: s_patch, temporal: "1", channels: n_vis_channels, align: <resize factor> }}, segment: item, source_anchor: "<processor file:lines>" }}
              - {{ name: vision, template: <tower_name>, inputs: [vision.patchify] }}
        ```
        When to use this vs. the inline-block pattern above (MTP):
          - MTP head is a STACK of `n_mtp_layers` identical blocks
            (`repeat: n_mtp_layers`),
            each block has a non-trivial DAG (enorm || hnorm → concat).
            → inline `blocks:` + `repeat:` on the group, one block
              definition.
          - Vision/audio tower is ONE self-contained subsystem invoked
            ONCE at the model root, even if it has an internal repeat
            (`resblocks × n_vis_layers`) — that internal repeat lives INSIDE the
            wrapper, not on the outer group.
            → draft wrapper component + singleton invocation.
          - Tower whose internal stack MIXES block types (MiMo-V2.5 /
            V2.6 vision: full-attention blocks at
            `vision_config.fullatt_block_indexes`, windowed blocks
            elsewhere): the aux group itself is the tower. Its `layers:`
            hold the stem ops, ONE stack with `repeat:` + `per_layer:`
            (the same `assign` / `map` the backbone uses), and the head
            ops; `checkpoint: {{prefix: <path-before-index>, index: local}}`
            sits on the group. The architecture view renders the group as
            one section. Reference: `models/mimo_v2_5.yaml`, layer
            `visual`.

  ❗ Whenever you set `group: true`, set exactly one primary `aux_kind:`:
  `mtp` / `vision` / `audio` / `speculative`. `speculative` means a non-MTP
  draft/verification stack; an MTP stack is always `mtp`. The field drives both
  the auxiliary-stack boundary and its architecture badge, and omission is a
  schema error. For an INDEXED aux stack, inspect the checkpoint tensor paths
  and declare its required address as
  `checkpoint: {{prefix: <path-before-index>, index: local}}` or
  `checkpoint: {{prefix: <backbone-path>, index: {{after: backbone}}}}`,
  the prefix written in full from the file root (`model.mtp.layers`). A
  non-indexed singleton aux wrapper has no index address; its `checkpoint`
  declares only the `root` its tensors hang off, when that differs from the
  model's. Do not infer this contract from `aux_kind`
  or the stack name.

---

**Phase 4 — VALIDATE & ITERATE (max 40 iterations).**

Goal: the validator returns top-level `valid: true`. That is the publish gate.
The one other end is `"blocked_by_engine": true` (below).

Validate checks the spec against the checkpoint and then replays the
analysis on a small set of standard deployments — one GPU, TP, EP with
DP-attention, context parallelism in each scheme the cache allows, and PP 2,
each in prefill and decode. `valid: true` means the spec analyses on all of
them. Each error names the node it is about. An `analysis_refusal` also names
the declaration that resolves it and the fix: edit that node as it says and
run validate again. An error of kind
`analysis_refusal_unattributed` names the node the analysis refused: compare
that node's op, operands and declared dims with what the forward source
computes there, and write it so that it computes the same. An error of kind
`analysis_engine_refusal` names a capability the engine does not yet support
for a construct the spec states correctly. Fix every other error.

validate prints one JSON object on stdout. When that JSON has
`"blocked_by_engine": true`, every remaining error is such a refusal and the
spec is complete: end your turn with a final message that names each
`capability` and its `node` from `analysis_refusals`.

Command: `{python} -m backend.inference.validate <model_id>`
(NEVER set `HF_HUB_OFFLINE=1` or `TRANSFORMERS_OFFLINE=1` — first call
takes 10-30s reading safetensors shard headers; results are cached on
disk so the second call is fast. Forcing offline silently returns
empty metadata; the weight gate then fails with
`Could not fetch model_storage_bytes from safetensors`, and the useful numeric
diff is unavailable.)

Parse the JSON output + stderr:
  • `valid: true` means all enforced checks passed. In particular, storage
    bytes must match and every checkpoint tensor must be covered. Before
    committing, also resolve or explain non-gating `unmatched_spec_nodes` and
    `shape_mismatches`; they are review diagnostics, not conditions used to
    compute `valid`.
  • Otherwise read:
      - a `checkpoint_name_absent` error → a tensor the spec stores under a
        name the checkpoint does not hold; it lists the header's tensors in
        that module, whose spelling the node's name and its stack's
        `checkpoint:` address should follow.
      - `param_mismatches[i].ratio_hint` → if several nodes cluster at the
        same ratio ("0.5×", "3×", ...), ONE dim binding is off by that
        factor. Find which binding (`d_ffn_expert`, `d_ffn_shared`,
        `n_experts`, `n_zero_experts`, `n_experts_active`) and fix it.
      - `unmatched_hf_tensors` → tensors the spec doesn't cover (missing
        sub-module / wrong Phase 2 component choice).
      - `shape_mismatches[i]` → cross-input geometry violation on a
        multi-input op. Each entry has `kind`:
          * `concat_dim_mismatch`: a `concat` got inputs whose
            non-axis dims disagree. Common cause: forgot a
            `head_broadcast` on a shared (1-head) tensor before
            joining it with a per-head tensor in 4-D.
            Look at `shapes` to see exactly where the rank/dim
            broke (e.g. `[1,64,1,128] | [1,8,1,64]` says input1
            has 8 heads but input0 has 64).
          * `contracted_axis_mismatch`: an op got inputs
            whose contracted axis disagrees — `detail` names the axis
            (`d_head` between Q and K, `s_kv` between the probabilities
            and V) and both extents. Q and K must both end on the same
            head width after head_split / RoPE / concat — a common cause is
            mixing Q's `d_qk_nope + d_qk_rope` with K's `d_qk_nope`
            (forgot to RoPE-pad K).
        These are pure dataflow geometry bugs — params often line
        up while the actual tensor shapes don't compose. Fix the
        upstream node that produced the mismatched shape; re-run.
      - `axiom_warnings[i]` → every entry is gating: facts about the cache
        each component call grows. `swa_cache_unbounded` means a
        sliding-window `cache.family` with a cached tensor that grows without
        a cap — put a `sliding_window_kv` over every cached stream, K and V
        alike.
        `windowing_declared_but_unmodelled` means an active
        `config.sliding_window` but no attention call keeps a capped cache.
        `axiom_unjudged` means the model's analysis failed; fix the analysis
        error reported beside it.
      - `type_contract_warnings[i]` → declared attention/cache consistency;
        every entry is gating.
      - `selection_read_errors[i]` → a score wired with a `select` operand
        (a top-k) reads keys whose cached tensor keeps a dense read law;
        gating. State the cap on the cached node (`read_topk:` on a
        `token_pool_compressor`) — every layer that scores under a top-k,
        not only the first one you wrote.
      - `reuse_warnings[i]` → two of your drafts are mostly the same graph,
        or a draft is mostly a library component. Write the shared structure
        once and bind what differs per call through `params:` slots (a slot
        can bind a zero-weight component that reads a stream another layer
        published), or bind the library component (a `when:` switch covers
        an optional weightless step). Not gating, but a copy is where one
        variant silently drifts from the others. This is the same comparison
        `{python} -m backend.arch.component_reuse <draft.yaml>` answers on one
        file, so you can check a fix without re-running the whole validator —
        and asking it BEFORE writing a draft is how this warning stays empty.
      - `model_card_warnings[i]` → no parameter count the model card states
        is near the analysis's, for totals or for activated counts. Read what
        the card counts (a backbone without lookup tables, activated per
        prompt token vs per decoded token) and check what your spec makes a
        token touch. Not gating; explain a remaining difference in your
        report.
  Change ONE thing per iteration; re-run the validator; repeat.

**When the spec language cannot state what the source does**: say so — do
not compensate. A number written where the config states it (read a
per-layer list entry as `config.<list>.<i>` into a dim of your own instead),
a model dim rebound to mean something else, or a draft copied per variant
because a part of it cannot be switched off, all pass the checkpoint anchors
and come out wrong elsewhere. A missing primitive is a gap file (below); any
other missing capability goes in the `# UNRESOLVED:` block with the source
line it concerns.

**Escape hatch (CRITICAL — avoid step-budget exhaustion)**: after **40
iterations** of the validator, if `valid` is false OR either unmatched list is
non-empty OR `shape_mismatches` is non-empty, STOP iterating. At the
top of your spec.yaml, write a `# UNRESOLVED:` comment block explaining:
    (a) what you've tried (each fix and its effect on the numbers),
    (b) the remaining diff value + specific `checkpoint_name_absent` /
        `ratio_hint` entries that remain unresolved,
    (c) your current hypothesis about what's missing.
Then EXIT. Do NOT keep looping with no new insight — the remaining step
budget won't suddenly produce a breakthrough, and a hand-reviewed
partial spec with a clear status marker is far more useful than an
infinite loop.

## Primitive Operations

These are the atomic compute ops. Components compose them into sub-DAGs.
The "Computes" column is a human math label copied from each `OpSpec.formula`
and may use conventional operand letters such as Q, K, D, S, or M. Those are
not authorable dim symbols. Only the descriptive names in "Required Dims" and
`backend/arch/dims.yaml` belong in YAML bindings.

{ops_doc}

### Required-dims contract

Each row's "Required Dims" column lists the dim keys the op's
`flops_fn` / `params_fn` reads. The BlockGraph loader
statically checks the required keys literally named `in`, `out`, or `dim` at
YAML load time and rejects with a friendly "Node X (op=Y) is missing required
dim binding(s): ..." error. Other required keys are not all globals: inherit a
registered top-level model dim when that is the same quantity, or bind a
call-site-local key such as `k` under the node's `dims:`. Missing keys outside
the three-name load check can instead fail later during evaluation.

So when authoring a node, always provide the local keys explicitly:

```yaml
# Good — `in` and `out` bound on the linear's call site:
proj:    {{ op: linear, in: x, dims: {{ in: d_model, out: d_model }}, weight_axes: [{{ replicated: true }}, {{ replicated: true }}] }}
# Good — `dim` shorthand for single-dim ops:
norm:    {{ op: rmsnorm, in: x, dim: d_model, weight_axes: [{{ replicated: true }}] }}
# Good — `in` (reduced-axis size) bound for sum_reduce:
collapse: {{ op: sum_reduce, in: weighted, axis: 2, dims: {{ in: n_hidden_copies }} }}
```

### Multi-output primitive ops (`<node>.<port>` references)

Some primitives produce multiple distinct tensors. Their "Outputs"
column lists `out + <port1>, <port2>, ...`. Downstream nodes can
reference any port via `<node>.<port>` — bare `<node>` resolves to
the main `out` port.

Example (`hc_split_sinkhorn` — a sinkhorn-style multi-output kernel
producing `pre / post / comb`):

```yaml
hc_attn_split:
  op: hc_split_sinkhorn
  in: [hc_attn_fn, hc_attn_scale, hc_attn_base]
  dims: {{ d_hc_mix: d_hc_mix, n_hidden_copies: n_hidden_copies }}
# `hc_attn_split` (no port) == `hc_attn_split.pre` — the main "out" port.
hc_attn_pre:    {{ op: hc_weighted_reduce, in: [x, hc_attn_split],          dims: {{ n_hidden_copies: n_hidden_copies, d_model: d_model }} }}
# `.post` and `.comb` are secondary ports — explicit reference.
hc_attn_post:   {{ op: hc_combine,         in: [attn, x, hc_attn_split.post, hc_attn_split.comb], dims: {{ n_hidden_copies: n_hidden_copies, d_model: d_model }} }}
```

Do NOT use `<node>.<port>` syntax against a single-output op — it
falls back to bare-ref interpretation and the spec validator will
reject it as an unknown node name. Port references are supported by registered
ops whose "Outputs" column lists them, by `custom_ops` that declare
`secondary_outputs`, and by wrapper components whose top level declares a
`secondary_outputs: {{port: internal_ref}}` map.

### Custom primitive ops (`custom_ops:` block) — declare new primitives in YAML

When the model uses an algorithmic kernel that no registered primitive
above can express (sinkhorn projection, custom recurrence, novel
indexer, …), declare it under `custom_ops:` in the spec or component YAML —
**you do NOT need to add an entry to `backend/arch/ops.py`**.

The custom op runs through the same engine paths as registered primitives. A
multi-output example:

```yaml
custom_ops:
  vendor_sinkhorn_split:             # name referenced as `op: vendor_sinkhorn_split`
    flops: "B * s_ctx * (2 * d_hc_mix + 80 * n_hidden_copies**2)"   # SymPy expression over bound dims
    params: "0"
    signature:                        # ordered input arity + shape templates
      mixes: [B, s_ctx, d_hc_mix]
      scale: [3]
      base:  [d_hc_mix]
    couples_on: [d_hc_mix]
    shape_kind: axis_replace          # main `out` port: last axis becomes n_hidden_copies
    out_key: n_hidden_copies
    secondary_outputs:                # multi-output ports (referenced as `<node>.<port>`)
      post: [B, s_ctx, n_hidden_copies]
      comb: [B, s_ctx, n_hidden_copies, n_hidden_copies]
    formula: "split mixes·scale + base by n_hidden_copies, n_hidden_copies, n_hidden_copies²; pre = σ(·) + ε, post = 2σ(·), comb = sinkhorn(softmax(·))"
    description: "Why this can't decompose into existing primitives."
```

Optional knobs in `custom_ops:`:

| field | when to use |
|---|---|
| `secondary_outputs: {{ port: [shape] }}` | the kernel produces ≥2 distinct tensors that downstream nodes need separately (e.g. a sinkhorn-style split that produces `pre / post / comb`) |
| `weight_tensor_suffix: ""` | the on-disk weight is stored as a naked `nn.Parameter` (no `.weight` suffix), not `nn.Linear`. Forward code looks like `self.W = nn.Parameter(...)` + `F.linear(x, self.W)` |
| `weight_shape: [n_vocab, d_model]` | the op bears a weight whose geometry is not the default `(out, in)` linear — e.g. `[d_model]` for a norm scale, `[n_vocab, d_model]` for an embedding |
| `carries_recurrent_state: true` | the kernel is a recurrence that owns state streamed across decode steps; every node running it must be named as the `carrier:` of a `cache.entries` state (see schema.md) |

Unknown keys are rejected. What you may declare is exactly what builds an
`OpSpec`: the signature, the shape kind, the cost expressions, the weight
geometry. `couples_on` is required and names signature shape labels that the
kernel joins/reduces/repartitions across; write `[]` for a fully separable op.
A kernel whose behavior needs anything else — sharding modes, KV
positions per query, view/comm status, a dtype override, an output shape only
Python can compute — is not authorable in a spec; it belongs in
`ops.py::register_op`, where it can carry that Python.

The validator runs at spec-load time with full context (custom_ops
table bound), so a typo like `vendor_sinkhorn_split.podt` (real port is
`post`) is rejected with: `Node 'X' references port '...podt', but
custom_op 'vendor_sinkhorn_split' declares secondary_outputs=['post', 'comb']`.

When to escalate to `ops.py`: if a second model adopts the same kernel,
a maintainer can promote your spec-scoped `custom_ops:` entry to a
global `OP_REGISTRY` registration. Until then, keep it spec-scoped.

## Component Library

Reusable compound components live in `backend/arch/components/`,
split into three physical tiers:

- `library/` — distinct topology building blocks. New models compose
  from here. May carry a model-family prefix in their name (e.g.
  `gemma4_4norm_scaled_block`) as a "first observed in" historical
  label, but the component itself is not scoped to that family — any
  model with matching topology may use it.
- `adapters/` — pure binding + checkpoint-naming shims around a library
  component for one model's checkpoint naming. They contribute no new graph
  structure of their own (just `op: <library_name>` + `params:` +
  `module:` / `inner_modules:`). Read them for reference; only reuse inside
  the same model family.
- `drafts/` — **agent-authored components for the model you're
  generating right now.** This is where YOU write any new component YAML
  files. Drafts are SCOPED to the model spec: only specs that list a draft
  name under their top-level `drafts:` field can see it, and only for that
  spec's load. Merged drafts from main are also shown in the manifest below;
  unlike your fresh output files they are read-only and must still be opted
  in with `drafts:`.

### Hard rules for new components

1. NEVER write new component yaml under `library/` or `adapters/`. Those
   are review-gated tiers a maintainer manages — your additions there
   leak into every other model and cannot be cleaned up scoped.
2. ALL new components MUST go to `components/drafts/<name>.yaml`.
3. Every draft name MUST appear under your spec yaml's top-level
   `drafts: [...]` list (see template below). Without the entry the
   loader cannot see the file and reports your component as unknown.
4. NEVER reference, read, or mention any Python tooling around drafts
   (you do not need to know how the loader scopes drafts, how files get
   reviewed, or how they later move tiers — that's the maintainer's
   job). Read YAML only. Running the commands this prompt gives you
   (`backend.inference.validate`, `backend.arch.structure`,
   `backend.arch.component_reuse`) is not reading tooling; their source
   stays out of bounds.
5. **When a component you author calls another component (a shared-expert
   FFN: `shared_experts: {{ op: swiglu_ffn, repeat: n_shared_experts }}`),
   AND your component declares a different `role:` than the inner one
   (typically `role: ffn_moe` wrapping a `role: ffn_dense` FFN), you MUST
   set `role: <your_outer_role>` on the call site:**

   ```yaml
   # in your MoE wrapper's graph:
   shared_experts: {{ op: swiglu_ffn, role: ffn_moe, in: x, repeat: n_shared_experts }}
   #                                  ↑↑↑↑↑↑↑↑↑↑↑↑↑↑
   #                                  required so inner leaves inherit ffn_moe,
   #                                  which is what `quant_context.per_role.ffn_moe`
   #                                  targets for FP4/FP8 routing.
   ```
   Without this, leaves under the inner FFN inherit `ffn_dense` from
   `swiglu_ffn`'s declaration, and any model spec's
   `quant_context.per_role.ffn_moe: {{ method: fp4 }}` (or similar) will
   never reach those leaves — silent quant misroute that shows up as a
   ≈2× spec-vs-actual storage diff for FP4 experts. The loader's
   role-propagation check warns about violations at boot.

```yaml
# in your spec yaml — drafts: list comes BEFORE the schema body
drafts:
  - <name1>
  - <name2>
match: ...
model: ...
```

The manifest below lists each EXISTING `library/`, `adapters/`, and merged
`drafts/` component by name + role + one-line description.
**Read the YAML file** (`backend/arch/components/<tier>/<name>.yaml`)
when you need the full graph — picking the right component depends on
its internal topology, tensor naming, and dim signature, not just the
name. Which file is worth opening is what
`{python} -m backend.arch.component_reuse <component.yaml>` answers: it
compares a graph against every component listed here by edges and names the
closest ones. Adding a new component is the last resort after the authoring
priority above; first verify that no formal or merged component (read it!)
matches your model's forward source.
Authoring an adapter is appropriate when an existing library
component's structure fits but the checkpoint uses different node
naming.

## Formal Base Inventory

These are the reviewed model YAML stems in `backend/arch/models/`. `base:` may
point only at one of these names (or omit `base:` in a self-contained spec).
Read a candidate before using it; the identity claim is only a navigation aid.

{formal_bases}

### Source is ground truth for COMPUTE. Checkpoint is ground truth for NAMING.

A spec describes two things that aren't the same: a forward
computation graph (what depends on what, what FLOPs are computed) AND
a set of tensor names that the analyzer matches against the
checkpoint's `safetensors.index.json`. They commonly diverge because
the checkpoint was produced by some training framework (Megatron-Core,
internal vendor stack, …) whose storage layout doesn't have to match
HF transformers' `modeling_*.py`. Examples:

- **Stacked-expert weights**: an MoE layer's experts may be a single
  `nn.Parameter` of shape
  `[n_expert_copies, 2*d_ffn_expert, d_model]` in the checkpoint (no
  `.weight` suffix, no `.experts.X.` indexing) while the HF source
  reads as `nn.ModuleList([SwiGLU(...) for _ in range(n_experts)])`.
- **Bare `nn.Parameter` instead of `nn.Linear`**: e.g. DSv3's routing
  gate is a Parameter directly on the MoE module (`mlp.gate.weight`,
  no `.linear.` indirection), but the forward graph still treats it
  like a Linear's matmul.
- **Asymmetric subgraphs in one model**: Qwen3.5's main backbone uses
  stacked-Parameter experts (perf path) while its MTP head uses a
  per-expert ModuleList (standard path). Same `modeling_*.py` class,
  two checkpoint layouts.
- **Quantization wrappers**: GPTQ/AWQ/compressed-tensors append
  suffixes (`*_qweight`, `*_scale_inv`, `*_packed`) that don't appear
  in the original `nn.Module` hierarchy.

Discipline: read HF source for the forward graph (library), then
**cross-check against `safetensors.index.json`** before committing
node names. If a node's expected `<id>.weight` doesn't appear in the
checkpoint, the issue is naming (write/extend an adapter), not
structure (don't bend the library component to match).

{components}

{schema_doc}

## Reference Examples

Study these carefully — your output must follow the same format.

{examples}
