# Changelog

All notable changes to floDl will be documented in this file.

The format is based on [Keep a Changelog](https://keepachangelog.com/),
and this project adheres to [Semantic Versioning](https://semver.org/).

## [Unreleased]

### Added

#### `Trainer`: primary training entry point

`Trainer` is the new default API for training in flodl. It forwards to the same DDP machinery as `Ddp::*` but reads as "just train" rather than "set up DDP" — the one-liner works transparently on 1 or N GPUs.

- **`Trainer::setup(&model, builder, optimizer)`** — one-call setup for Graph-based models, replacing `Ddp::setup()`. Auto-detects hardware, distributes if multi-GPU, sets optimizer, enables training mode. Zero DDP overhead on single GPU / CPU.
- **`Trainer::setup_with(&model, builder, optimizer, config)`** — same but takes a `DdpConfig` for explicit El Che cadence / speed hints / overhead target. Replaces `Ddp::setup_with()`.
- **`Trainer::builder(model_factory, optim_factory, train_fn)`** — builder entry for framework-managed training. Replaces `Ddp::builder()`. Works identically on single or multi-GPU.
- `flodl::Trainer` re-exported from the crate root alongside `Ddp`.

Motivation: `Ddp::builder()` read as an opt-in for "when you have multiple GPUs," obscuring that the same entry is the sensible default for single-GPU training too. `Trainer::builder()` makes the intent explicit — reach for it by default; drop to `Ddp::wrap()` when you need explicit multi-GPU control (GAN, RL, progressive patterns).

#### flodl-hf: loss wiring on BERT-family task heads

All nine `*For{SequenceClassification,TokenClassification,QuestionAnswering}` heads across BERT, RoBERTa, and DistilBERT can now drive a training loop without any hand-rolled loss plumbing.

- **Free functions in `flodl_hf::task_heads`** (family-agnostic, compose with flodl's existing loss idiom):
  - `sequence_classification_loss(logits, labels)` - CE over `[batch, num_labels]` logits with `[batch]` indices or `[batch, num_labels]` soft labels.
  - `token_classification_loss(logits, labels)` - CE over flattened `[batch*seq_len, num_labels]` logits with `-100` ignore on `[batch, seq_len]` labels, matching HF Python's convention for specials / padding / non-first subwords.
  - `question_answering_loss(logits, start_positions, end_positions)` - averaged CE on the split `[batch, seq_len, 2]` logits.
- **`forward_encoded(enc) -> Variable` on every head** returns raw logits without touching train / eval mode, leaving the caller (or `Trainer::setup`) in charge of mode.
- **`compute_loss(enc, labels)` on every head** combines `forward_encoded` with the matching task-head loss. Mirrors HF Python's `model(..., labels=...).loss` one-call pattern for `/port`-friendly fine-tune loops.
- **New example**: `fdl flodl-hf example distilbert-finetune` - loads the SST-2 DistilBERT checkpoint, fine-tunes on an inline 10-example polarity dataset for 5 steps, prints the loss curve and a final eval probe. Self-contained (no dataset download at example-runtime), CPU-only, about 30 s after the one-time weight fetch.

#### `Trainer::setup_head` + `HasGraph` trait: transparent DDP for task-head wrappers

`Trainer::setup_head` extends the transparent 1-or-N-GPU story to wrapper types like `flodl-hf`'s `BertForSequenceClassification`. Same call shape as `Trainer::setup` (`head, factory, optimizer`), same training-loop code path, works identically on CPU / single GPU / multi-GPU.

- **`flodl::HasGraph` trait**: one method, `fn graph(&self) -> &Graph`. Any wrapper that owns a flodl `Graph` can opt into graph-aware DDP machinery by implementing it (3 lines). `Graph` itself implements it trivially.
- **`Trainer::setup_head(head, head_factory, optimizer)`** (and `setup_head_with` for explicit `DdpConfig`): prints device summary, distributes via the head factory for additional GPUs, wires the optimizer, enables training mode. On 1 GPU or CPU the factory is never called; on N GPUs each replica is a fresh head built at its device.
- Internally routes through a small `HeadReplica<H>` adapter that delegates `Module::parameters/buffers/set_training/as_graph` to the inner graph. Task heads stay free of a direct `impl Module` (their true forward is multi-input via `forward_multi` and doesn't fit the single-Variable `Module::forward` signature).
- All nine flodl-hf task heads (BERT / RoBERTa / DistilBERT × SeqCls / TokenCls / QA) now implement `HasGraph` and expose a `config()` accessor so callers can build replicas inside the factory closure.
- The `distilbert-finetune` example is rewritten to use `setup_head`: the loop is byte-identical to the multi-GPU path, so a user can scale to N GPUs without changing any training code.

### Deprecated

- `Ddp::setup()`, `Ddp::setup_with()`, `Ddp::builder()` — use the matching `Trainer::*` methods instead. Same behavior, clearer intent. Compile-time deprecation warnings guide migration. `Ddp::wrap()` remains on `Ddp` as the explicit multi-GPU control tier. Removal targeted for a future release.

## [0.5.2] - 2026-04-22

### Added

#### flodl-hf: new sibling crate for HuggingFace integration
Scaffolded under `flodl-hf/` with feature-gated modules so downstream users can take only what they need. Transformer blocks build on flodl's `nn` module; the crate depends on `flodl` for `Tensor`, `Module`, and named-parameter machinery.

- **Three install profiles**:
  - *Full* (default): `safetensors` + `hf-hub` + `tokenizers`. `flodl-hf = "0.5.2"` loads `"bert-base-uncased"` out of the box.
  - *Vision-only*: `hub` feature only. For ViT, CLIP vision towers, or any image model that doesn't need tokenisation. Drops regex + unicode surface.
  - *Offline / minimal*: no default features. `safetensors`-only. For air-gapped environments, embedded training, or local-disk pipelines — no network, no async runtime, no TLS stack.
- **`cuda` feature** on `flodl-hf` re-exports `flodl/cuda`.
- **HTTP backend**: `ureq` + `rustls-tls` on `hf-hub = "0.4"`. Sync, no tokio, no openssl (dev Docker image has no `libssl-dev`, so rustls is now the convention for any HTTP dep).
- **ROADMAP**: HF fine-tuning moved to `In progress` with `[started]` marker; `flodl-manager CLI evolution` line added to Possibilities (gaps flagged while scaffolding: `fdl build` argv forwarding, `fdl add <crate>` command).

#### flodl-hf: HuggingFace-naming foundations

- **`flodl-hf::path::HfPath`** — immutable dotted-path builder that assembles HuggingFace-style keys segment by segment. Authors write short identifiers (`root.sub("encoder").sub("layer").sub(i).sub("attention").sub("self").leaf("query")`) instead of `format!` boilerplate. `sub` accepts anything `ToString`, so integer layer indices compose directly. `new`/`sub`/`leaf` panic on invalid segments (programmer error); `try_new`/`try_sub`/`try_leaf` return `Result` for user-supplied input (LoRA adapter names, custom head names from config, HF `get_submodule` paths). Validation rejects empty segments and embedded `.` / `/`.
- **`flodl-hf::path::hf_key_from_flodl_key`** — converts flodl's `"{tag}/{leaf}"` qualified names (from `Graph::named_parameters()`) to HuggingFace-dotted keys by swapping only the final `/` for `.`. Centralises the flodl ↔ HF boundary in one place.
- **`flodl-hf::safetensors_io::LoadValidation`** — three-bucket key-set diff (`missing`, `unused`, `shape_mismatches`) with stable sorted output. `into_result()` emits a loud `TensorError` listing up to 20 entries per bucket with a `"... and N more"` truncation tail, surfacing every disagreement in a single error instead of failing on the first mismatch. Catches the entire `"queri"` vs `"query"` typo class: the bad tag appears as `missing`, the real checkpoint key as `unused`, pointing straight at the fix.
- **`flodl-hf::safetensors_io::expected_from_graph`** — walks a `Graph`'s named parameters + buffers and returns the HF-key + shape list needed by `validate_keys`.

#### flodl-hf: BERT architecture

Full HuggingFace BERT stack under `flodl-hf/src/models/bert.rs`: `BertConfig` (with a `bert_base_uncased()` preset), `BertEmbeddings`, `BertSelfAttention` (fused `scaled_dot_product_attention` with in-kernel dropout), `BertSelfOutput`, `BertAttention`, `BertIntermediate`, `BertOutput`, `BertLayer`, `BertPooler`, `BertModel`.

- **`BertModel::build` / `BertModel::on_device`** — returns a flodl `Graph` with `embeddings → N encoder layers → pooler`. The graph takes **4 inputs**: `input_ids`, `position_ids`, `token_type_ids`, and a pre-computed additive `attention_mask` shared across all encoder layers via `.using()`.
- **Only `BertLayer` implements `Module`**; inner composites carry ad-hoc `forward` signatures matching their real semantics (residual inputs). Not pretending residuals are single-input. Parameter aggregation is explicit via `HfPath::prefix_params`.
- **`build_extended_attention_mask(mask)`** helper: raw `[B, S]` 0/1 → additive `[B, 1, 1, S]` f32 (`0.0` attend, `-1e4` mask, fp16-safe). Callers run this once before `forward_multi`, mirroring HF Python's explicit `get_extended_attention_mask` idiom.
- **HF-compatible parameter naming**: tags encode HF dotted paths directly; `Graph::named_parameters() + hf_key_from_flodl_key` yields `"bert.encoder.layer.0.attention.self.query.weight"` on the first run. BERT-base has **199 parameters** total — pinned by a test.

#### flodl-hf: safetensors weight loader

`flodl-hf/src/safetensors_io.rs` — `load_safetensors_into_graph(graph, bytes)` plus rename-aware and allow-unused variants (`*_with_rename`, `*_with_rename_allow_unused`, `*_file_*` path-based).

- **Strict-load semantics**: `validate_keys` runs first; any disagreement bails before mutating any parameter. Either the graph is fully loaded or fully untouched. Makes safe retry / fall-back possible.
- **`Variable::set_data` over `copy_`**: libtorch rejects in-place ops on leaf Variables that require grad. `set_data` swaps storage while preserving `requires_grad` — the documented "optimizer replacement" path. `Buffer::set` is the buffer equivalent.
- **Host-side dtype conversion** supports F32 / F64 / BF16 / F16 → f32, including a custom `f16_bits_to_f32` (normals, subnormals, Inf, NaN) so the loader doesn't drag in the `half` crate.
- **Integer dtypes rejected loudly** (`I8`/`I16`/`I32`/`I64`/`U*`/`BOOL`/`F8*`). Silent casts hide upstream bugs.
- **`bert_legacy_key_rename`** handles pre-2020 BERT checkpoints' legacy `LayerNorm.gamma` / `LayerNorm.beta` → `weight` / `bias`. The rename-aware loader checks injectivity and raises a loud error on collision.

#### flodl-hf: HuggingFace Hub integration

- **`BertModel::from_pretrained(repo_id)` / `::from_pretrained_on_device(repo_id, dev)`** — one-liner weight + config pull via `hf_hub::api::sync::Api`. Parses `config.json`, builds the matching `Graph`, loads safetensors weights via the allow-unused rename-aware loader. The 7 `cls.*` task-head keys in `bert-base-uncased` (it's a `BertForPreTraining` checkpoint) are logged and discarded (up to 20 with a truncation tail).
- **`HfTokenizer::from_pretrained(repo_id)`** — downloads `tokenizer.json` via the same `hf_hub` cache. Feature-gated on both `hub` and `tokenizer`.
- **`fdl test-live`** — root-level command that runs `cargo test live -- --nocapture --ignored`. Canonical runner for `_live`-suffixed `#[ignore]`'d tests that need network / external resources. See `feedback_live_test_naming.md`.

#### flodl-hf: `HfTokenizer` (model-agnostic wrapper)

`flodl-hf/src/tokenizer.rs` — thin façade over `tokenizers::Tokenizer`.

- **`from_file(path)` + `from_pretrained(repo_id)`** (the latter gated on the `hub` feature).
- **`encode(&[&str])` / `encode_on_device(&[&str], Device)`** return an `EncodedBatch` carrying `input_ids` / `attention_mask` / `token_type_ids` / `position_ids` as `i64 [B, S]` Variables.
- **Sensible padding defaults** installed on load when `tokenizer.json` hasn't configured padding itself: `BatchLongest`, direction `Right`, `pad_id = token_to_id("[PAD]").unwrap_or(0)`. **No default truncation** — oversized texts error loudly at the model rather than silently truncate.
- **Model-agnostic**: one wrapper serves BERT, GPT2, LLaMA, etc. The loaded `tokenizer.json` carries the model-specific pre-tokenizer and post-processor. For BERT, the raw 0/1 `attention_mask` still needs `build_extended_attention_mask` before `forward_multi`.

#### flodl-hf: PyTorch forward-parity infrastructure

`flodl-hf/` is now a self-contained sub-project with its own child `fdl.yml`. The root `fdl.yml` picks it up via the convention `flodl-hf:` entry (same shape as `ddp-bench:`).

- **`fdl flodl-hf parity-bert`** regenerates the committed parity fixture:
  - `flodl-hf/scripts/Dockerfile.parity` (`python:3.12-slim` + torch 2.8.0 CPU wheel + `transformers ~4.46` + `safetensors ~0.4` + `huggingface-hub ~0.26`).
  - `flodl-hf/scripts/parity_bert.py` — loads `bert-base-uncased`, forces `torch.nn.attention.SDPBackend.MATH` for determinism, writes inputs + outputs + provenance metadata (`source_model` / `source_sha` / `torch_version` / `sdpa_backend`) to `flodl-hf/tests/fixtures/bert_base_uncased_parity.safetensors` (~16 KB).
- **`flodl-hf/tests/bert_parity.rs`** → `bert_parity_vs_pytorch_live`. Asserts `max_abs_diff ≤ 1e-5` on `pooler_output` vs the HF Python reference. Observed on the reference host: **9.835e-7** (well under the 1e-5 tolerance, 10x headroom).
- **`flodl-hf/tests/tokenizer_parity.rs`** → `bert_tokenizer_matches_parity_fixture_live`. Asserts `HfTokenizer` reproduces the exact pinned `input_ids` + `attention_mask` + `token_type_ids` from the parity fixture — `"hello world"` → `[101, 7592, 2088, 102]`. Closes the `text → tokens → BertModel → HF reference` loop end-to-end.
- **`docker-compose.yml` gains the `hf-parity` service** (mounts workspace, `HF_HOME=/workspace/.hf-cache` for persistent weight / tokenizer cache; gitignored).
- Both parity gates run via `fdl test-live`.

#### flodl-hf: runnable examples

- **`flodl-hf/examples/`** with a child `fdl.yml`, surfaced as `fdl flodl-hf example <name>`. Cleanly separates user-facing demos from dev tooling (`parity-bert`).
- **`flodl-hf/examples/bert_embed.rs`** — closed-loop example: `HfTokenizer::from_pretrained` → `BertModel::from_pretrained` → `forward_multi` → per-sentence pooled embeddings. Prints `dim=768 L2=… head=[…]` for each input text in a batch.
- **Cargo `[[example]]` stanzas** carry `required-features = ["hub", "tokenizer"]` so `--no-default-features` builds skip the example cleanly. Adding an example is three yml lines + one Cargo stanza.

#### flodl-hf: BERT task heads

Three fine-tuned heads on top of `BertModel`, each with a Laravel-flavoured `predict()` / `answer()` API and live parity tests against real Hub checkpoints. All three load with one line (`from_pretrained(repo_id)`), pulling weights, config, and tokenizer in one go. No per-head tokenizer setup, no separate `AutoTokenizer` call.

- **`BertForSequenceClassification`** — `pooler_output → Dropout → Linear(hidden, num_labels)`. Parameter keys `classifier.{weight,bias}`. `predict(&[&str])` returns `Vec<Vec<(String, f32)>>` sorted descending by probability, with label names from the checkpoint's `id2label` (or `LABEL_k` fallback). Works out of the box with emotion / sentiment / toxicity / NLI fine-tunes such as `nateraw/bert-base-uncased-emotion`, `nlptown/bert-base-multilingual-uncased-sentiment`, `unitary/toxic-bert`.
- **`BertForTokenClassification`** — `last_hidden_state → Dropout → Linear(hidden, num_labels)`. Parameter keys `classifier.{weight,bias}`. `predict(&[&str])` returns `Vec<Vec<TokenPrediction>>` with `{ token, label, score, attends }` per sub-token; the `attends` flag mirrors the attention mask so padding drops cleanly. Works with `dslim/bert-base-NER`, `dbmdz/bert-large-cased-finetuned-conll03-english`, etc.
- **`BertForQuestionAnswering`** — `last_hidden_state → Linear(hidden, 2)` splitting into start/end logits. Parameter keys `qa_outputs.{weight,bias}`. `answer(question, context)` / `answer_batch(&[(q, c)])` return `Answer { text, start, end, score }` with the extracted span decoded through the attached tokenizer. Span search is restricted to context tokens (`token_type_id == 1`) so the question region can't be answered-with-itself. Works with `csarron/bert-base-uncased-squad-v1` and other SQuAD fine-tunes.
- **`BertConfig` extended** with `num_labels: Option<i64>` and `id2label: Option<Vec<String>>`, parsed from `config.json`. Non-contiguous label ids (gap, duplicate) error loudly — silently reindexing would misalign names with logits rows.
- **`BertModel::on_device_without_pooler`** — mirrors HF Python's `add_pooling_layer=False`. Emits `last_hidden_state` (`[B, S, H]`) instead of pooled output; the shape token-classification and QA heads consume. Backed by a shared private `bert_backbone_flow` helper so `BertModel` and every task head build on one source of truth.
- **`HfTokenizer::encode_pairs(&[(&str, &str)])`** — paired encoding with `token_type_ids == 1` on the second segment. Required for QA; also useful for NLI and sentence-pair classification.
- **Parity infrastructure per head**:
  - `fdl flodl-hf parity-bert-seqcls` / `parity-bert-tokencls` / `parity-bert-qa` regenerate fixtures under `flodl-hf/tests/fixtures/bert_{seqcls,tokencls,qa}_parity.safetensors` against `nateraw/bert-base-uncased-emotion` / `dslim/bert-base-NER` / `csarron/bert-base-uncased-squad-v1` respectively. Each script pins a text input, forces the MATH SDPA backend, records source SHA + torch version in metadata. The SeqCls script chains through `convert_bin_to_safetensors.py` first because the emotion checkpoint is `.bin`-only.
  - Matching `_live` integration tests (`bert_seqcls_parity_vs_pytorch_live`, `bert_tokencls_parity_vs_pytorch_live`, `bert_qa_parity_vs_pytorch_live`) assert `max_abs_diff ≤ 1e-5` on logits against the HF reference. Run via `fdl test-live`.
- **Runnable examples**: `fdl flodl-hf example bert-classify` / `bert-ner` / `bert-qa`. Each demo loads a real fine-tune, runs a small pinned batch, prints the top labels / entities / extracted spans.

#### flodl-hf: RoBERTa architecture + task heads

`flodl-hf/src/models/roberta.rs` — full RoBERTa stack (`RobertaConfig`, `RobertaEmbeddings`, encoder layer, pooler, three task heads). Same attention + FFN shape as BERT, four load-bearing deltas that make RoBERTa-family checkpoints load cleanly without per-model tokenizer or input plumbing.

- **`RobertaModel::from_pretrained(repo_id)`** — one-liner weight + config pull mirroring the BERT path. **Returns a pooler-free backbone by default** (`last_hidden_state` of shape `[B, S, hidden]`) since `roberta-base` and most fine-tunes don't ship pooler weights — RoBERTa pretraining drops BERT's NSP objective. HF Python silently random-initialises the pooler on load, which makes `pooler_output` non-reproducible; flodl-hf takes the opposite default and keeps the weight load strict. `RobertaModel::on_device` is still available for checkpoints that do carry their own pooler.
- **Position ids computed internally** from `input_ids` using HF's padding-offset convention (`padding_idx + cumsum(mask) * mask`; real tokens start at `padding_idx + 1`). The graph takes **3 named inputs** (`input_ids`, `token_type_ids`, `attention_mask`) — no `position_ids` in the signature, matching HF Python's `RobertaModel.forward`. Callers don't need to know the quirk exists.
- **`RobertaForSequenceClassification`** — uses the HF-native two-layer head on the `<s>` hidden state: `Dropout → dense → tanh → Dropout → out_proj`. Parameter keys `classifier.dense.{weight,bias}` + `classifier.out_proj.{weight,bias}` — not a single `classifier.{weight,bias}` like BERT. Works with `cardiffnlp/twitter-roberta-base-sentiment-latest`, `roberta-large-mnli`, `SamLowe/roberta-base-go_emotions`.
- **`RobertaForTokenClassification`** — same `Dropout → Linear` shape as BERT's token-classification head; loads `Jean-Baptiste/roberta-large-ner-english`, `obi/deid_roberta_i2b2`, etc. `predict(&[&str]) → Vec<Vec<TokenPrediction>>`.
- **`RobertaForQuestionAnswering`** — `qa_outputs.{weight,bias}` head. `answer(question, context)` / `answer_batch(&[(q, c)])` return `Answer { text, start, end, score }`. Span search is restricted to `sequence_id == 1` (see below), since RoBERTa's `token_type_ids` are uniformly zero and can't distinguish question from context. Works with `deepset/roberta-base-squad2`.
- **`RobertaConfig::from_json_str`** parses all shape + task-head fields. Defaults track HF's `RobertaConfig`: `layer_norm_eps = 1e-5` (not BERT's `1e-12`), `type_vocab_size = 1`, `pad_token_id = 1`, `max_position_embeddings = 514` (holds `padding_idx` row + 512 real positions).
- **Parity infrastructure per head**: `fdl flodl-hf parity-roberta` / `parity-roberta-seqcls` / `parity-roberta-tokencls` / `parity-roberta-qa` regenerate fixtures under `flodl-hf/tests/fixtures/roberta_*.safetensors` against `roberta-base`, `cardiffnlp/twitter-roberta-base-sentiment-latest`, `Jean-Baptiste/roberta-large-ner-english`, and `deepset/roberta-base-squad2`. Matching `_live` integration tests assert `max_abs_diff ≤ 1e-5` on pooled output / logits against the HF reference. Run via `fdl test-live`.
- **Runnable examples**: `fdl flodl-hf example roberta-embed` / `roberta-classify` / `roberta-ner` / `roberta-qa`.

#### flodl-hf: shared encoder layer + `LayerNaming` abstraction

`flodl-hf/src/models/transformer_layer.rs` introduces a single `TransformerLayer` module reused across BERT, RoBERTa, and DistilBERT. The three families share the same mathematical encoder block (self-attention + residual + LayerNorm, two-layer GELU FFN + residual + LayerNorm); only the HF weight-key suffixes differ. `LayerNaming` carries the per-family mapping as a `const` struct of 8 static strings, swapped at construction time.

- **`LayerNaming::BERT`** covers both BERT and RoBERTa (`attention.self.{query,key,value}`, `attention.output.dense`, `attention.output.LayerNorm`, `intermediate.dense`, `output.dense`, `output.LayerNorm`).
- **`LayerNaming::DISTILBERT`** maps to DistilBERT's flatter layout (`attention.{q_lin,k_lin,v_lin,out_lin}`, `sa_layer_norm`, `ffn.{lin1,lin2}`, `output_layer_norm`).
- `bert.rs` and `roberta.rs` collapsed from ~1800 + ~1250 lines to their embeddings + pooler + task heads; six duplicated encoder-layer structs per family (`*SelfAttention`, `*SelfOutput`, `*Attention`, `*Intermediate`, `*Output`, `*Layer`) replaced by one shared implementation. Existing parity tests gate the refactor at `max_abs_diff <= 1e-5` vs HF Python on 8 pinned checkpoints; numbers unchanged by the collapse.

#### flodl-hf: DistilBERT architecture + task heads

`flodl-hf/src/models/distilbert.rs` ships the 6-layer distilled BERT family (`DistilBertConfig`, `DistilBertEmbeddings`, `DistilBertModel`, three task heads). Encoder block shared with BERT / RoBERTa via `LayerNaming::DISTILBERT` (see above). Load-bearing deltas from the BERT port:

- **`DistilBertModel::from_pretrained(repo_id)`** returns a pooler-free `Graph` taking **2 named inputs**: `input_ids` (implicit) + `attention_mask`. No `token_type_ids` (DistilBERT is single-segment; the embedding table doesn't exist) and no `position_ids` (sequential `0..S` computed internally via `Tensor::arange + reshape + expand`). Callers ignore both quirks.
- **`DistilBertConfig::from_json_str`** reads HF's native field names exactly: `n_layers` / `n_heads` / `dim` / `hidden_dim` rather than BERT's `num_hidden_layers` / `num_attention_heads` / `hidden_size` / `intermediate_size`. HF docs cross-reference friction-free; the encoder instantiation pays a tiny adapter cost. Plus the two DistilBERT-specific dropouts `qa_dropout` (typical `0.1`) and `seq_classif_dropout` (typical `0.2`), and `sinusoidal_pos_embds` (parsed but unused: HF Python overwrites the sinusoidal init with the checkpoint's learned positions, so every public checkpoint ships a trained table).
- **`DistilBertForSequenceClassification`** uses HF's two-layer head on the first token's hidden state: `select(CLS) -> pre_classifier (dim -> dim) -> ReLU -> Dropout(seq_classif_dropout) -> classifier (dim -> num_labels)`. Parameter keys `pre_classifier.{weight,bias}` + `classifier.{weight,bias}` are siblings at the root level, not nested. Works with `lxyuan/distilbert-base-multilingual-cased-sentiments-student` (3-class sentiment, multilingual).
- **`DistilBertForTokenClassification`** — `last_hidden_state -> Dropout -> Linear(dim, num_labels)`. Parameter keys `classifier.{weight,bias}`. `predict(&[&str]) -> Vec<Vec<TokenPrediction>>`. Works with `dslim/distilbert-NER` (PER / ORG / LOC / MISC BIO, 9 labels).
- **`DistilBertForQuestionAnswering`** — `last_hidden_state -> Dropout(qa_dropout) -> Linear(dim, 2)`. Parameter keys `qa_outputs.{weight,bias}`. `answer(question, context)` / `answer_batch(&[(q, c)])` return `Answer { text, start, end, score }`; span search restricted to `sequence_ids == 1` (reuses the model-agnostic filter added with `EncodedBatch.sequence_ids`). Works with `distilbert/distilbert-base-cased-distilled-squad`.
- **Parity infrastructure per head**: `fdl flodl-hf parity-distilbert` / `parity-distilbert-seqcls` / `parity-distilbert-tokencls` / `parity-distilbert-qa` regenerate fixtures under `flodl-hf/tests/fixtures/distilbert_*.safetensors` against the four pinned checkpoints. Matching `_live` integration tests assert `max_abs_diff <= 1e-5` on logits / hidden state. Observed on the reference host: `distilbert-base-uncased` backbone **1.431e-6**, `lxyuan/*-sentiments-student` SeqCls **2.384e-7** (42x headroom), `dslim/distilbert-NER` TokenCls **3.815e-6**, `distilbert/distilbert-base-cased-distilled-squad` QA **2.623e-6**.
- **Runnable examples**: `fdl flodl-hf example distilbert-embed` / `distilbert-classify` / `distilbert-ner` / `distilbert-qa`.

#### flodl-hf: AutoModel family dispatch

One-liner Hub loading over the BERT / RoBERTa / DistilBERT families without the caller having to know which family the checkpoint belongs to. Dispatches on `config.json`'s `model_type` field, mirroring HF Python's `AutoModel` / `AutoModelForSequenceClassification` / … entry points.

- **`flodl-hf::models::auto::AutoConfig`** — enum over `BertConfig` / `RobertaConfig` / `DistilBertConfig`, parsed by `AutoConfig::from_json_str`. Dispatches on `model_type` (`bert` / `roberta` / `distilbert`). Unsupported values (`modernbert`, `xlm-roberta`, `electra`, …) surface a loud error naming the offending type and listing the supported set. A new `config_json::required_string` helper backs the dispatch read.
- **`AutoModel::from_pretrained(repo_id)` / `::from_pretrained_on_device`** — returns a `Graph`. Routes BERT through `BertModel::on_device_without_pooler` so the output is always `last_hidden_state` of shape `[batch, seq_len, hidden]`, consistent across the three families. Diverges intentionally from HF Python's `BertModel.from_pretrained` (which includes the pooler); when BERT's pooler output is specifically needed, use `BertModel::from_pretrained` directly. The returned graph's `forward_multi` input count still varies by family (BERT: 4, RoBERTa: 3, DistilBERT: 2); callers that run the graph directly need to match that, the task-head wrappers below hide it.
- **`AutoModelForSequenceClassification` / `AutoModelForTokenClassification` / `AutoModelForQuestionAnswering`** — enums over the per-family concrete heads. `from_pretrained(repo_id)` dispatches loading; `predict(&[&str])` / `answer(question, context)` / `answer_batch(&[(q, c)])` run inference with a unified signature. `with_tokenizer` and `graph()` / `labels()` accessors delegate to the inner head. The same code path serves `bert-base-uncased`, `roberta-base`, and `distilbert-base-uncased`.
- **Runnable example**: `fdl flodl-hf example auto-classify -- <repo_id>`. Default: `cardiffnlp/twitter-roberta-base-sentiment-latest`; pass any BERT / RoBERTa / DistilBERT classification checkpoint as `argv[1]`. Same three-line caller regardless of family.
- **No new parity fixtures**: AutoModel is a pure dispatch layer over already-tested per-family paths. Unit tests cover `AutoConfig::from_json_str` dispatch for all three families plus unknown-model-type and malformed-input error cases.

#### flodl-manager: `fdl add flodl-hf` scaffold + `fdl init --with-hf`

Closes the "very rustic" discovery gap. Before today, a user with a fresh flodl project couldn't find flodl-hf without reading docs, editing their `Cargo.toml` manually, and guessing the right feature flavors. Now one command drops a working playground.

- **`fdl add flodl-hf` (alias: `fdl add hf`)** — scaffolds a `./flodl-hf/` sub-crate inside the current flodl project. Standalone cargo crate with its own `Cargo.toml` + `src/main.rs` (a one-file `AutoModel` classifier that takes a repo id from argv) + `fdl.yml` with runnable commands (`classify`, `bert`, `distilbert-sentiment`, plus `build` / `check` / `shell`) + `README.md` documenting the three feature flavors (full / vision-only / offline), the `fdl flodl-hf convert` workflow for `.bin`-only repos, and how to wire flodl-hf into a main crate when the user is ready.
- **Version lockstep**: the scaffold parses the host project's `flodl = "X.Y.Z"` dependency (plain, table, or workspace-inherited form) and pins `flodl-hf` to the matching `=X.Y.Z`. Git-only and path-only flodl deps error with actionable guidance rather than silently picking a version.
- **Scope contract**: no mutation of the user's root `Cargo.toml` or `fdl.yml`. The playground is a side crate for hands-on discovery; wiring flodl-hf into the user's main code stays their call. The generated README walks through it.
- **Idempotent**: refuses to overwrite an existing `./flodl-hf/` directory. Users delete explicitly if they want a regenerate.
- **`fdl init --with-hf`** and **interactive prompt**: `fdl init` now asks "Include flodl-hf (HuggingFace: BERT/RoBERTa/DistilBERT, Hub loader, tokenizer)?" after the Docker/native choice. `--with-hf` bypasses the prompt for scripted invocations; any explicit `--docker` / `--native` / `--with-hf` flag puts init in non-interactive mode, respecting `--with-hf` verbatim.
- **Templates live in `flodl-cli/src/scaffold/`** — baked into the `fdl` binary via `include_str!` at compile time and travel inside the `flodl-cli` crate tarball, so `cargo install flodl-cli` from crates.io drops a fully functional `fdl add`. The scaffold `Cargo.toml` is stored as `Cargo.toml.in` to prevent cargo treating the sub-directory as a nested package during `cargo package`; it is written out as `Cargo.toml` when the scaffold runs.
- **Host-project mode detection**: `fdl add flodl-hf` inspects the parent dir to decide how to wire the scaffolded commands. `docker-compose.yml` present → Docker mode, scaffolded `fdl.yml` keeps `docker: dev` on each cargo command so `fdl classify` dispatches into the `dev` service. `docker-compose.yml` absent → Native mode, `docker:` lines stripped so `fdl classify` runs `cargo run --release` directly on the host. The invariant `fdl.yml` (or `fdl.yml.example`) must be present is enforced loudly: a missing fdl config aborts the scaffold with "expects an initialised flodl project". `.bin`-to-safetensors conversion is documented as a direct Python invocation in the scaffold README (`pip install torch transformers safetensors` + inline script) rather than assuming the rdl-repo-internal `fdl flodl-hf convert` Docker service is available in user projects.
- **First slice of the broader flodl-manager roadmap line**: deliberately narrow. `fdl add` supports only `flodl-hf` today; per-model feature flavors (`fdl add hf --for bert|vit|offline`), `fdl build` / `clippy` argv forwarding, and `fdl doctor` / `model-info` stay on the roadmap for follow-up arcs.

#### flodl-hf: `EncodedBatch.sequence_ids` + model-agnostic QA span filter

- **`EncodedBatch` gains `sequence_ids: Variable`** — per-token segment tag from the HF tokenizer (`0` = first sequence, `1` = second sequence, `-1` = special / padding). This is the canonical HF signal for "which part of a pair encoding does this token belong to"; it's model-agnostic, where `token_type_ids` is a model input whose semantics vary (BERT sets segment B to 1; RoBERTa keeps everything at zero).
- **`BertForQuestionAnswering::extract` switched** from `token_type_ids == 1` to `sequence_ids == 1` for context-region filtering. Behaviour is bit-identical on BERT (the tokenizer sets both equal), but the same code now works across the full BERT family.

#### flodl: `LayerNorm` with custom epsilon
- **`LayerNorm::with_eps`** and **`LayerNorm::on_device_with_eps`** — constructors accepting a custom epsilon, required for HuggingFace BERT (`eps = 1e-12`) and any architecture deviating from the PyTorch `1e-5` default.
- **`LayerNorm::DEFAULT_EPS`** associated constant.
- Hand-computed golden-value test anchors the eps-reaches-the-kernel claim (not just "doesn't panic").

#### flodl: Native `torch.embedding` FFI with `padding_idx`
- **FFI chain**: `flodl_embedding` shim in `flodl-sys/{shim.h, ops_training.cpp, src/lib.rs}` → `Tensor::embedding(weight, indices, padding_idx)` → `autograd::embedding(weight, indices, padding_idx)`. Delegates to libtorch's `at::embedding` directly, replacing the previous `index_select + reshape` manual path in `Embedding::forward`.
- **`Embedding::with_padding_idx`** and **`Embedding::on_device_with_padding_idx`** — constructors accepting `Option<i64>`. The gradient of the `padding_idx` row is masked to zero during backward by the native kernel, so the PAD embedding doesn't drift during fine-tuning. Range-checked at construction.
- **`Embedding::NO_PADDING = -1`** associated constant (sentinel matching `at::embedding`'s convention).
- For LLaMA-style checkpoints where `pad_token_id == eos_token_id`, pass `padding_idx = None` — otherwise the EOS row freezes, silently breaking fine-tuning.
- `Embedding::forward` now handles indices of any shape, returning `[*indices.shape, embedding_dim]` without manual reshape.

#### flodl: `scaled_dot_product_attention` FFI

Full FFI chain adding fused attention to flodl. Used internally by `BertSelfAttention`; available to any flodl model that wants fused softmax(QKᵀ/√d)V + optional masking + optional dropout.

- **`flodl_scaled_dot_product_attention`** shim in `flodl-sys/{shim.h, ops_nn.cpp, src/lib.rs}`.
- **`Tensor::scaled_dot_product_attention(q, k, v, attn_mask: Option<&Tensor>, dropout_p, is_causal, scale: Option<f64>)`** in `flodl/src/tensor/nn_ops.rs`.
- **`autograd::scaled_dot_product_attention(...)`** (re-exported as `flodl::scaled_dot_product_attention`) — backward via native libtorch autograd, same `Variable::wrap` pattern as `embedding`.
- Sentinel conventions: `attn_mask = None` for no mask; `scale = None` (or any `Some(x)` with `x <= 0.0`) selects the default `1/sqrt(E)`.
- Parity test `test_sdpa_parity_vs_naive` anchors the fused kernel against a hand-rolled `softmax(QKᵀ/√d)V` implementation; `test_sdpa_backward` covers the autograd path.
- libtorch 2.10.0; SDPA shipped in 2.0, so safe under any supported variant.

### Changed

- **`Embedding::forward` input dtype**: the preferred input is now `i64`. The legacy f32-indices path is kept as a fallback but emits a one-shot stderr deprecation warning (`"[flodl] deprecated: Embedding::forward received non-i64 indices; this fallback will be removed in a future release. Pass i64 tensors via Tensor::from_i64."`) the first time it fires per process. Internal tests that previously used `from_f32` indices have been migrated to `Tensor::from_i64`.

### Fixed

- **DDP test flake under full-suite CUDA contention**: `distributed::ddp_run::tests::test_epoch_fn_called_per_epoch` and `::test_epoch_fn_set_lr` now explicitly use `ApplyPolicy::Sync`. Both assumed `count == num_epochs * world_size`, which only holds in Sync mode: under the default `Cadence`, progressive dispatch lets a fast rank drain an epoch's pool past a slow rank's share, so the slow rank legitimately receives fewer `StartEpoch` events. Designed behaviour for progressive streaming; the test assumption was wrong.
- **`fdl cuda-test-all` / `cuda-test-serial` pulled in `_live` tests**: the "remaining ignored" leg ran `cargo test --ignored --skip nccl --skip graph_distribute`, which swept up the new HuggingFace `_live` parity tests along with the intended CUDA Graph / manual_seed / probe tests. `--skip _live` added to both commands in `fdl.yml` and `fdl.yml.example`. Live tests are the sole domain of `fdl test-live`.

### Removed

- **`Embedding` struct fields `num_embeddings` and `embedding_dim`** — both were stored but never read after the move to `at::embedding`. Fields were private; no user-visible impact.

## [0.5.1] - 2026-04-19

### Added

#### `fdl init --native` and interactive mode selection
- **Three scaffold modes**, mutually exclusive: default (Docker with host-mounted libtorch), `--docker` (Docker with libtorch baked into the image), `--native` (no Docker; libtorch and cargo on the host).
- **Interactive prompt** via `util::prompt::ask_yn` + `ask_choice` when no flag is passed and a TTY is available: asks whether to use Docker, then (if yes) whether libtorch should be host-mounted or baked in. Non-interactive invocations default to mounted.
- **Native scaffold** skips `Dockerfile` / `Dockerfile.cuda` / `docker-compose.yml`; `fdl.yml.example` omits the `docker:` field so every command runs directly on the host. Next-steps message points at `./fdl libtorch download --cpu` / `--cuda 12.8` for host-side libtorch provisioning.

#### Release-readiness suite (`make release-check`)
- **`ci/release/`** (new): eight self-contained shell scripts each verifying one release-gate invariant, plus a `run-all.sh` orchestrator. Scripts: `01-git` (clean tree, tag available), `02-version-sync` (Cargo.toml matches a dated CHANGELOG header), `03-lint-docs` (stale `make` refs, hardcoded user paths, dangling `fdl <cmd>` references in docs), `04-shell` (`sh -n` / `bash -n` picks interpreter from shebang, optional `shellcheck`), `05-ci` (delegates to `fdl ci`), `06-scaffold` (delegates to `make test-init`), `07-docs-rs` (delegates to `make docs-rs`), `08-publish-dry` (`cargo publish --dry-run` per workspace crate in dep order).
- **`make release-check`**: orchestrator target that prints a pass/fail summary and exits non-zero on any failure. Designed to catch the exact bug class this release fixed (removed `make bench*` / `bench-cpu` leftovers across docs and source code).
- **`docs/release.md`** (new): release process doc — pre-flight checklist, script table, common failures, post-tag steps (`git push --tags`, `cargo publish` dep order).
- **Side-fixes uncovered by the linter and folded in**: `flodl-cli/src/libtorch/{build,download}.rs` printing `Run 'make cuda-test' to verify.` → `fdl cuda-test`; 23 `#[ignore = "... run with: make cuda-test-*"]` test attribute messages across `flodl/src/distributed/*.rs` and `flodl/src/nn/cuda_graph.rs` → `fdl cuda-test-*`; `Dockerfile.cuda.source` + embedded copy comments referencing `make build-libtorch` → `fdl libtorch build`.

#### Post-init / post-setup "install globally?" prompt
- **`util::install_prompt::offer_global_install`**: new helper that fires at the end of `fdl init` and (interactive) `fdl setup`. Offers to promote the running binary to `~/.local/bin/fdl` so subsequent invocations can drop the `./` prefix. Skips itself when already installed at the target path, when a different `fdl` is already there, or when `HOME` is unresolvable. Declining prints a single-line reminder (`(later: ./fdl install)`).

#### Auto-probe for non-cargo entries
- **`flodl-cli/src/config.rs::load_command`**: when a sub-command's schema cache is stale or missing **and** its `entry:` is not a cargo command, `fdl` probes `<entry> --fdl-schema` automatically and caches the result under `<cmd-dir>/.fdl/schema-cache/<cmd>.json`. Scripts and pre-built binaries become first-class schema sources without an explicit `fdl schema refresh` round-trip on a fresh clone. Cargo entries remain explicit-only: `cargo run --fdl-schema` triggers a full compile, which is unacceptable latency for `fdl <cmd> --help`.
- Probe failures are swallowed: an entry that doesn't implement `--fdl-schema` simply falls through to the inline YAML schema (or no schema). Help always renders.
- New tests in `config::tests`: `load_command_auto_probes_non_cargo_entry_and_writes_cache`, `load_command_skips_auto_probe_for_cargo_entries`, `load_command_auto_probe_failure_falls_through_silently`.

### Changed

#### Scaffold is now fdl-native
- **`fdl.yml.example`** (new, committed): shipped by every scaffold mode with 8-10 commands (the exact set depends on mode). fdl auto-copies it to the gitignored `fdl.yml` on first run.
- **`./fdl` bootstrap** now shipped in **all three modes** (previously mounted-only): `./fdl install` promotes it to `~/.local/bin/fdl`.
- **Scaffold `.gitignore`** now ignores `fdl.yml` and `fdl.yaml` alongside the existing cargo/libtorch paths.
- **`fdl init` next-steps message** rewritten: `./fdl build / test / run / shell` replaces the old `make build / test / run / shell`, with a mode-specific first step (`./fdl setup`, `./fdl build`, or `./fdl libtorch download --cpu`).
- **`fdl setup`** post-install hints: `make cuda-test / cuda-build / cuda-shell` and `make test / build / shell` became the `fdl` equivalents.

#### `init.sh` reduced to a thin `fdl` proxy
- **Dropped**: the separate Docker/make dependency checks (fdl itself handles these where they still apply; scaffolded projects no longer need `make`), the hardcoded `--docker` flag, and the custom post-scaffold instructions.
- **Kept**: the "download the pre-compiled binary, fall back to `cargo build`" bootstrap for the `curl ... | sh -s <name>` path. After obtaining the binary the script simply `exec "$CLI" init "$@"`, so every flag (`--docker`, `--native`, the interactive prompt) behaves the same as running `fdl init` directly.
- **`$FDL_BIN`** (new, opt-in): when set to an executable path, `init.sh` skips the download and execs that binary instead. Used by `make test-init` to smoke-test the current checkout rather than the last-released binary on GitHub.
- **`make test-init`** rewritten: builds `flodl-cli` via cargo, scaffolds a `--docker` project through `init.sh` with `$FDL_BIN` pointed at the fresh binary, verifies every expected file is present, and runs `docker compose config` as a generated-config sanity check. Dropped the previous `make image` + live-container cargo-cache-write step (the scaffold no longer ships a `Makefile`, and the real integration path is exercised by `fdl test` separately).

#### `download-libtorch.sh` reduced to a thin `fdl libtorch download` proxy
- **Dropped**: the entire platform detection / URL construction / zip extraction / `.arch` and `.active` writer / shell-setup-instructions machinery (305 lines of logic duplicated from `flodl-cli/src/libtorch/download.rs`).
- **Kept**: the bootstrap-fdl-binary flow + `$FDL_BIN` override (same pattern as `init.sh`). After obtaining the binary: `exec "$CLI" libtorch download "$@"`.
- **Legacy `--project` flag**: filtered out with a `note:` to stderr. `fdl libtorch download` auto-detects whether to install into the project's `./libtorch/` or `$FLODL_HOME/libtorch/` based on where it's invoked from, so the explicit flag is redundant.

#### Benchmark pipeline: `fdl bench` is now the entry point
- **`benchmarks/fdl.yml`** (new): entry-kind sub-command with three presets: `publish` (10 interleaved rounds, 15s warmup), `cpu` (CPU-only quick run), and `cpu-publish`. Replaces the two root-level `run:`-kind commands.
- **`benchmarks/run.sh`** emits its option schema via `--fdl-schema`, handled at the top of the file before `set -euo pipefail`. `fdl bench --help` now lists `--rounds`, `--lock-clocks`, `--warmup-secs`, `--output`, `--cpu`, `--tier1`, `--tier2`, `--bench <NAME>`.
- **Root `fdl.yml` / `fdl.yml.example`**: `bench:` is now a path-kind pointer to `./benchmarks/`; `bench-cpu` removed (superseded by the `cpu` preset).
- **`benchmarks/bench-publish.ps1`** calls `fdl bench publish --rounds X --lock-clocks Y --output Z` instead of the removed `make bench-publish` target. Repo root inside WSL is discovered via `wsl wslpath -a (Resolve-Path "$PSScriptRoot\..").Path`, no hardcoded path.
- **`ddp-bench/run-missing.sh`**: hardcoded repo path replaced with `cd "$(dirname "$0")/.."`.
- **`docs/benchmark.md`**: four `make bench*` invocations rewritten as `fdl bench [<preset>]` plus a pointer to `fdl bench --help`.

#### Documentation and repo hygiene
- **`docs/cli.md`** `fdl init` section: three-mode invocation, updated file list (`fdl.yml.example` + `./fdl` bootstrap), removed the "scaffold ships a Makefile by default" caveat.
- **`docs/cli.md`** `fdl schema` / `--fdl-schema` section reframed around the two opt-in paths: `#[derive(FdlArgs)]` for Rust binaries, manual JSON emit for scripts and pre-built tools (with `benchmarks/run.sh` cited as the reference example). Clarifies that non-cargo entries auto-probe on first use, while cargo entries still require an explicit `fdl schema refresh` after rebuilds.
- **`docs/cli.md`** Benchmarks section (flodl-source-checkout context): updated to the `fdl bench [<preset>]` surface.
- **`ai/skills/port/guide.md`** + embedded copy **`flodl-cli/assets/skills/port-guide.md`**: Phase 0 rewritten to reflect the fdl-native scaffold (`./fdl build / test / cuda-test` instead of `make *`). "Option A" is now labelled "Mounted libtorch (recommended)".
- **`benchmarks/README.md`**: quick-start and publication-mode invocations rewritten for `fdl bench [<preset>]`.
- **`.github/pull_request_template.md`**: `make test` / `make clippy` checkboxes swapped for `fdl test` / `fdl clippy`.
- **Blog posts** (`site/_posts/2026-03-25-benchmarks.md`, `site/_posts/2026-03-31-benchmark-update.md`): short update notes added pointing at `docs/benchmark.md` for the current `fdl bench [<preset>]` invocations. Original prose preserved for historical accuracy.

### Removed

- Root `fdl.yml` / `fdl.yml.example`: `bench-cpu` command (use `fdl bench cpu` instead).
- **Scaffolded `Makefile`** (both `MAKEFILE_DOCKER` and `MAKEFILE_MOUNTED` in `flodl-cli/src/init.rs`): projects generated by `fdl init` are now fdl-native. The commands the Makefile used to wrap (`build`, `test`, `run`, `check`, `clippy`, `shell`, `cuda-*`) now live in the scaffolded `fdl.yml.example`. The libtorch env-var derivation that lived in the mounted Makefile is handled once inside `flodl-cli/src/run.rs::libtorch_env` for every dispatch.

## [0.5.0] - 2026-04-18

> Upgrading from 0.4.0? The only breaking changes live in `fdl.yml`
> (`scripts:` merged into `commands:`) and in `#[derive(FdlArgs)]`
> (a small set of reserved flag names). See
> [UPGRADE.md](UPGRADE.md) for the step-by-step migration.

### Added

#### New Crate: `flodl-cli-macros`
- **`flodl-cli-macros/`** (new workspace member): proc-macro derive crate exposing `#[derive(FdlArgs)]`, re-exported as `flodl_cli::FdlArgs`. Turns a plain struct into an argv parser plus schema and help renderer. Implements `flodl_cli::FdlArgsTrait` with `try_parse_from(&[String]) -> Result<Self, String>`, `schema() -> flodl_cli::Schema`, and `render_help() -> String`.
- **`#[option(...)]`** named-flag attribute: `short = 'c'`, `default = "..."`, `choices = &["a", "b"]`, `env = "VAR"`, `completer = "name"`. Supported field shapes: `bool` (absent = false, present = true), `T` (scalar, requires `default`), `Option<T>` (absent = None), `Vec<T>` (repeatable).
- **`#[arg(...)]`** positional attribute: `default`, `choices`, `variadic` (requires `Vec<T>`, must be last), `completer`.
- **Derive-time validation**: required positionals cannot follow optional ones; variadic must be last; reserved flags cannot be shadowed (see Global Flags for the authoritative list); duplicate long/short flags error at compile time.
- **Per-option env fallback**: `#[option(env = "WANDB_API_KEY")]` falls back to the environment variable when the flag is absent (argv > env > default). `bool` fields are exempt.
- **Typed help via Rust docs**: doc-comments on the struct and fields flow into `render_help()` output with ANSI colouring.

#### `fdl.yml` Manifest Overhaul
- **Unified `commands:` map**: replaces the separate `scripts:` + `commands:` pair from 0.4.0. Each entry is exactly one of three kinds, chosen by which fields are set.
- **`run:` kind**: inline shell script, optionally wrapped in `docker compose run --rm <service>` when `docker:` is set. Closed script: extra argv is **not** forwarded (use shell `$VAR` inside the script instead).
- **`path:` kind**: pointer to a nested directory with its own `fdl.yml`. Convention default: when the entry is empty and a sibling `<name>/` directory exists, `fdl` loads `<name>/fdl.yml`. Extra argv after `fdl <cmd> ...` flows through to the nested `entry:` and is validated against the `FdlArgs` schema.
- **preset kind**: neither `run:` nor `path:` set; inline `ddp:` / `training:` / `output:` / `options:` fields deep-merge over the enclosing sub-command's defaults and invoke its `entry:`. Only legal inside a path-kind sub-command's own `fdl.yml`.
- **Load-time validation**: `docker:` on non-`run:` entries is rejected; unknown keys error with a clear message; kind-mismatch (e.g. both `run:` and `path:`) errors loudly.
- **Auto-bootstrap**: when only `fdl.yml.example` or `fdl.yml.dist` is present, `fdl` offers to copy it to the real (gitignored) `fdl.yml`.

#### Environment Overlays (`--env`)
- **`--env <name>`** global flag: deep-merges `fdl.<name>.yml` over the base `fdl.yml` before resolving any command.
- **`FDL_ENV=<name>`**: equivalent environment-variable form.
- **First-arg convention**: `fdl ci test` applies the `ci` overlay when `fdl.ci.yml` exists AND the name does not collide with a command. Ambiguity errors loudly.
- **Loud vs. silent fallthrough**: explicit selectors (flag, env var) fail loudly when the overlay file is missing; the first-arg convention silently falls through so existing commands are never shadowed.
- **Per-layer origin annotations**: every merged field is tagged with the file and line that contributed it, visible via `fdl config show`.

#### New Top-Level Commands
- **`fdl config show [env]`**: prints the fully-resolved YAML config with per-layer origin annotations. Useful for previewing overlay behaviour before running a long job. Equivalent forms: `fdl config show ci`, `fdl --env ci config show`, `fdl ci config show`.
- **`fdl schema list`** / **`clear [<cmd>]`** / **`refresh [<cmd>]`**: manage the per-command schema cache that powers help, completion, and validation. `list --json` for machine-readable output. Fresh / stale / orphan status is reported for every cached entry.
- **`--fdl-schema`** (hidden probe flag): every binary built with `#[derive(FdlArgs)]` responds with a JSON description of its flags. `fdl` calls it as a subprocess and caches the result at `<cmd-dir>/.fdl/schema-cache/<cmd>.json`.
- **`--refresh-schema`** per-invocation flag: refreshes a single entry's cache on the next call without running `fdl schema refresh` explicitly. Handy during development.

#### Global Flags
- **`--env <name>`**: apply overlay (see above).
- **`--ansi`** / **`--no-ansi`**: force or disable ANSI color output, overriding TTY and `NO_COLOR` auto-detection.
- **Reserved flag set** (`--help`, `--version`, `--quiet`, `--env`, `-h`, `-V`, `-q`, `-v`, `-e`): cannot be shadowed by `FdlArgs`-derived structs. Enforced at derive time for clear errors.
- **`--help` is never blocked**: validation lives strictly on the exec path, scoped to the single command being invoked. Running `fdl <cmd> --help` never triggers manifest-wide validation.

#### Value-Aware Completions
- **`choices:` drives completion**: flag completion returns the declared set, e.g. `fdl libtorch download --cuda <TAB>` offers `12.6 12.8`; `fdl ddp-bench quick --model <TAB>` offers values from the `FdlArgs` schema.
- **Project-aware**: generated scripts reflect the current `fdl.yml`'s `commands:` (all three kinds) plus every sub-command's own nested entries.
- **`fdl autocomplete`**: one-shot installer that detects the user's shell and writes the completion script to the right location.

#### Styled Output
- **ANSI-coloured help**: `render_help()` assembles colour-annotated help from doc-comments and attribute metadata. Styles are centralised in `flodl-cli/src/style.rs`.
- **Help layout for presets**: preset sub-commands render under an **Arguments** heading as a single synthetic slot with values indented beneath (placeholder overridable via `arg-name:`); regular sub-commands render under **Commands** (run / path kinds only).

#### Schema Cache (`flodl-cli/src/schema_cache.rs`)
- Per-project cache at `<cmd-dir>/.fdl/schema-cache/<cmd>.json`, populated on first use of a `path:`-kind sub-command and refreshed on demand. Cache entries carry mtime + binary hash so `fdl schema list` can flag stale (binary newer than cache) and orphan (command removed from `fdl.yml`) states.

### Changed

#### Docs
- **`docs/cli.md`** rewritten: restructured around three contexts: standalone (no project), inside an `fdl.yml` project, inside the flodl source checkout. Standalone libtorch-manager examples now lead with PyTorch C++ (CMake / `CMAKE_PREFIX_PATH`) alongside the existing tch-rs walkthrough.
- **`docs/design/run-config.md`** expanded: formal schema for `fdl.yml`, sub-command resolution, overlay merge semantics, and the DDP / training / output to `DdpConfig` / `DdpRunConfig` mapping.
- **`docs/design/msf-cadence-control.md`** (new, 669 lines): design spec for the MSF cadence-control layer.
- **`flodl-cli/README.md`** rewritten: leads with "this is the flodl CLI"; standalone libtorch manager framed as a secondary use case.
- **`flodl-cli-macros/README.md`** (new): attribute reference for `#[derive(FdlArgs)]`.
- **Root `README.md`**: short pointer box advertising `fdl` as a standalone libtorch manager for tch-rs and PyTorch C++ users.

#### Dogfooding
- **`ddp-bench/src/main.rs`** ported to `#[derive(FdlArgs)]`: typed flags, shared schema with `fdl`, help / completion / validation all come from the derived parser. Replaces the hand-rolled argv handling.
- **`fdl.yml.example`** and **`ddp-bench/fdl.yml.example`** updated to the unified `commands:` shape with the three-kind distinction.

### Removed

- **`scripts:` key in `fdl.yml`**: merged into the unified `commands:` map. Any 0.4.0 `fdl.yml` that used `scripts:` must move its entries into `commands:` with an explicit `run:` field. The three-kind `commands:` model (`run:` / `path:` / preset) is now the long-term stable manifest surface; no further breaking changes to its shape are scheduled.
- **Shadowing of reserved CLI flags in `#[derive(FdlArgs)]` structs**: `--help`, `--version`, `--quiet`, `--env`, `-h`, `-V`, `-q`, `-v`, `-e` are now reserved and enforced at derive time. Structs in 0.4.0 that named fields with any of these flags silently overrode them; in 0.5.0 they fail to compile. Rename any affected fields.

## [0.4.0] - 2026-04-14

### Added

#### `ddp-bench` — DDP Validation Suite
- **New workspace member `ddp-bench/`**: End-to-end harness that reproduces published training setups to build scientifically valid solo baselines, then measures DDP/ElChe convergence quality against them.
- **8 reference models** (`ddp-bench/src/models/`):
  - `logistic` / `mlp` / `lenet` / `conv_ae` (MNIST)
  - `resnet` (ResNet-20 on CIFAR-10, He et al. 2015 — paper baseline 91.25%)
  - `resnet_graph` (FlowBuilder rewrite of ResNet-20: same parameter count, same accuracy, with graph-level observation, named parameters and tagged residual blocks)
  - `char_rnn` (Karpathy 2015 char-RNN on Shakespeare, LSTM-256x2)
  - `gpt_nano` (4-layer pre-norm Transformer on Shakespeare, warmup + cosine decay)
- **8 DDP modes**: `solo-0`, `solo-1`, `nccl-{sync,cadence,async}`, `cpu-{sync,cadence,async}`. Side-by-side validation across all backend × policy combinations.
- **Harness** (`harness.rs`): single-process and DDP launch paths, per-batch metric collection via `record_scalar`, per-epoch convergence summaries, baseline JSON I/O.
- **Analyzer** (`analyze.rs`): compares runs against committed baselines (`baselines/structured.json`, `baselines/baseline.json`, `baselines/sync.json`) with relative-error tolerances.
- **Reporter** (`report.rs`): generates Markdown convergence reports including loss curves and timing tables (`runs/report.md`, `ddp-bench/report.md`).
- **Dataset downloader** (`download.rs`): on-demand download + cache for MNIST, CIFAR-10, Shakespeare. Cache lives under `data/` (gitignored).
- CLI flags: `--list`, `--model <name|all>`, `--mode <mode|all>`, `--epochs N`, `--batch-size`, `--lr-scale F`, `--validate`, `--baseline <path>`, `--save-baseline`, `--report <path>`, `--seed`.

#### Built-in Standard Datasets — `flodl::data::datasets`
- **`Mnist`** (`data/datasets/mnist.rs`): parses IDX gzip into `[N,1,28,28]` Float32 + `[N]` Int64. `Mnist::parse(images_gz, labels_gz) -> Result<Self>`. Implements `BatchDataSet`.
- **`Cifar10`** (`data/datasets/cifar10.rs`): parses the binary batch format into `[N,3,32,32]` Float32 + `[N]` Int64 (10 classes). Implements `BatchDataSet`.
- **`Shakespeare`** (`data/datasets/shakespeare.rs`): char-level tokenizer for next-char prediction. `[N, seq_len]` Int64 over a 65-symbol vocabulary, plus a `decode(&[i64]) -> String` helper. Implements `BatchDataSet`.
- All three plug directly into `DataLoader::builder(dataset)` in single-GPU and DDP modes.

#### Convergence Guard — Unified Divergence Reaction
- **`convergence` module** (`flodl/src/distributed/ddp_run/convergence.rs`): unified weight-space divergence guard for both NCCL and CPU averaging paths.
- **`DivergenceReport`**: per-rank L2 deltas plus optional pre/post norms. Free decomposition into cosine similarities and magnitude shifts via the algebraic identity (no extra reductions).
- **`ConvergenceAction`**: `Stable` / `SuppressGrowth` / `NudgeDown { factor }` recommendations.
- **`ConvergenceGuard::new(policy, enabled, threshold)`**: 5-interval ring buffer. Detects 3-consecutive-rising trends above threshold and returns `SuppressGrowth` to freeze ElChe anchor/overshoot growth (rather than aggressively shrinking, which can kill convergence — overhead auto-tune handles loosening on its own).
- **Wired into `Coordinator`** for both NCCL and CPU paths (`Sync` is no-op, `Cadence`/`Async` use trend detection). Configurable via `DdpRunConfig::with_divergence_threshold(f64)`.
- Cross-rank divergence is now reset after every averaging event, fixing a stale-state bug that pinned the ElChe anchor at 1.

#### Timeline Profiler — `monitor::timeline`
- **`Timeline`** (`flodl/src/monitor/timeline.rs`): high-frequency (default 100ms poll, 1s broadcast) system + GPU profiler. Captures CPU, RAM, per-GPU compute utilization and VRAM as `TimelineSample`s, interleaved with training events.
- **`EventKind`**: `EpochStart` / `EpochEnd { loss }` / `SyncStart` / `SyncEnd { duration_ms }` / `CpuAvgStart` / `CpuAvgEnd { duration_ms }` / `AnchorChanged { from, to }` / `Throttle { rank }` / `Idle { device, duration_ms }` / `Custom { label }`.
- **API**: `Timeline::new(poll_ms)` / `with_intervals(poll_ms, broadcast_ms)` (returns `Arc<Timeline>`), `start()` / `stop()`, `event(EventKind)`, `subscribe()` for live `mpsc` updates, `summary()`, `idle_gaps(device, threshold_pct, min_ms)`, `drain()`, `sample_count()`.
- **Output**: `save_json(path)`, `save_csv(path)`, `save_html(path)` — the HTML view (`timeline.html`) renders a swimlane visualization of CPU/GPU utilization, sync/averaging events, anchor changes and detected idle gaps. Used by `ddp-bench` for every run (`runs/<model>/<mode>/timeline.html`).
- Enable per-job in `fdl.yaml` with `ddp.timeline: true` or `output.timeline: true`.

#### Verbosity-Gated Logging — `flodl::log`
- **`Verbosity` enum**: `Quiet (0)` / `Normal (1)` / `Verbose (2)` / `Debug (3)` / `Trace (4)`. Higher levels include lower.
- **Macros**: `flodl::msg!("...", args)` (Normal default, `@Verbose`/`@Debug`/`@Trace` for explicit level), plus `flodl::verbose!()`, `flodl::debug!()`, `flodl::trace!()`.
- **Routing**: Normal/Verbose go to **stdout**; Debug/Trace go to **stderr** so they remain unbuffered in Docker non-TTY environments. Errors keep using bare `eprintln!`.
- **Zero-code config**: `FLODL_VERBOSITY=verbose cargo run` (accepts integers 0–4 or names). Programmatic override via `flodl::log::set_verbosity(Verbosity)`.
- **CLI integration**: `fdl -v` / `-vv` / `-vvv` / `--quiet` set `FLODL_VERBOSITY` in the parent process so it flows into Docker child commands automatically.

#### FlowBuilder — `also_with`
- **`FlowBuilder::also_with(skip, main)`** (`flodl/src/graph/flow.rs`): residual connection with a custom skip path. Generalizes [`also`](../flodl/src/graph/flow.rs) for cases where the skip needs its own transform — e.g. ResNet downsample blocks where a 1×1 conv + BN matches channel/stride changes. Output is `skip(x) + main(x)`. Exercised by `ddp-bench/src/models/resnet_graph.rs` (ResNet-20 on CIFAR-10, full paper-accuracy baseline).

#### `AdaptiveAvgPool2d`
- **`AdaptiveAvgPool2d::new([h, w])`** (`flodl/src/nn/pooling.rs`): global / fixed-output-size average pooling. Counterpart to the existing `AdaptiveMaxPool2d`. `[1, 1]` gives global average pooling (common ResNet head before FC); arbitrary output sizes enable variable-size input support. Re-exported at crate root.

#### Metrics — `drain_scalars`
- **`flodl::drain_scalars() -> HashMap<String, (f64, usize)>`** (`flodl/src/distributed/ddp_run/mod.rs`): companion to the existing `record_scalar`. Flushes the thread-local accumulator and returns `(sum, count)` per tag so callers (monitors, custom loops) can average or log per-batch scalars outside the DDP coordinator path. Re-exported at crate root.

#### LR Scheduling — Cross-Mode Parity
- **`Graph::set_scheduler(Arc<dyn Scheduler>)`** and **`Graph::set_lr_scale(f64)`** (`flodl/src/graph/distributed.rs`): scheduler attached on the Graph DDP path drives the optimizer LR via `scheduler.lr(training_step) * lr_scale` on every `step()`. `training_step` advances per `step()` call. **`Graph::training_step()`** accessor exposed for monitoring.
- **`GpuWorker::set_scheduler` / `set_lr_scale` / `current_lr`** (`flodl/src/distributed/ddp_run/worker.rs`): same mechanism on the DDP-builder path. LR computed as `scheduler.lr(global_step + steps_since_avg) * lr_scale` per batch.
- **`DdpBuilder::scheduler(factory)`** (`flodl/src/distributed/ddp_run/orchestrator.rs:1219`): per-worker scheduler factory closure. Each rank instantiates its own scheduler (cheap to clone, no shared state). Pairs with `lr_scale_ratio` to keep all ranks in lockstep.
- **`DdpBuilder::lr_scale_ratio(f64)`** / **`DdpRunConfig::with_lr_scale_ratio(f64)`**: when set, the framework auto-computes the per-rank `lr_scale` from `world_size` (linear scaling rule, Goyal et al. 2017). Default `0.0` (= disabled, `lr_scale = 1.0`); set to `1.0` for full linear scaling, fractional values for sub-linear. Manual override stays available via `--lr-scale` in `ddp-bench`.
- **Cross-mode parity test** (`graph_tests.rs`): asserts that the same `MultiStepLR` produces identical LR trajectories across all three training paths — manual reference loop, `GpuWorker` (DDP builder), and `Graph::step()` — for both unscaled and `lr_scale != 1.0`.
- **Coordinator regression**: `SyncAck` no longer inflates `steps_since_avg` and now properly satisfies `nccl_ack`, fixing a scheduler drift across NCCL averaging events.

#### DDP — New Configuration Knobs
- **`DdpBuilder::no_divergence_guard()`** / **`DdpRunConfig::with_no_divergence_guard()`**: disable the convergence guard entirely. Use during calibration runs or when the divergence trend logging is more noise than signal. Default: enabled with `divergence_threshold = 0.05`.
- **`DdpBuilder::max_overshoot(usize)`** / **`DdpRunConfig::with_max_overshoot(usize)`**: cap how many extra batches the fastest rank can run past the slowest before the next averaging event in `Async` policy. Pairs with auto-tuning; set to bound the worst case explicitly. Async-only — the `Cadence` policy uses wall-time anchoring instead. The internal `overshoot_ceiling` (default ~3× anchor) gates the auto-tuner.
- **`DdpBuilder::timeline(Arc<Timeline>)`** / **`DdpRunConfig::with_timeline(Arc<Timeline>)`** / **`DdpConfig::timeline(Arc<Timeline>)`** / **`Graph::timeline(Arc<Timeline>)`**: attach a shared `monitor::Timeline` so the DDP runtime injects `EpochStart/End`, `SyncStart/End`, `CpuAvgStart/End`, `AnchorChanged`, `Throttle` events into the profiler stream. All four entry points (single-GPU Graph, manual `Ddp::wrap`, `Ddp::setup`, `DdpBuilder`) accept the same `Arc<Timeline>`. Used by `ddp-bench` to produce per-run swimlane HTML.
- **`Coordinator::builder()`** (`flodl/src/distributed/ddp_run/coordinator/mod.rs`): the coordinator now exposes a fluent builder (`progressive`, `batch_size`, `timeline`, `divergence_threshold`, `no_divergence_guard`, `overhead_target`, `max_anchor`, `checkpoint_every`, `snapshot_timeout_secs`, `epoch_metrics_tx`, `device_indices`, `num_epochs`, `partition_ratios`, `max_overshoot`, `overshoot_ceiling`, `build`). Internal — the user-facing surface is still `DdpBuilder`/`Ddp::setup` — but useful for writing custom orchestrators.
- **Note on `max_batch_diff`**: the field shipped in 0.3.0 (per-rank lockstep limit). What's new is `DdpBuilder::max_batch_diff(usize)` as a top-level fluent setter (was only reachable via `DdpRunConfig::with_max_batch_diff`).

#### CLI: `fdl run` and Project / Sub-command Manifests
- **`fdl.yaml`** (also `fdl.yml`, `fdl.json`): committed project manifest. Declares `description`, `scripts` (named shell commands with optional `docker:` service binding) and `commands` (paths to sub-command directories that have their own `fdl.yaml`). Example at the repo root: `fdl.yml.example` (84 lines).
- **Sub-command manifests** (e.g. `ddp-bench/fdl.yml.example`): declare `entry`, `docker`, structured `ddp` / `training` / `output` sections, and named `jobs` (presets that merge over the defaults). DDP section maps 1:1 to `DdpConfig` / `DdpRunConfig` (mode, policy, backend, anchor, max_anchor, overhead_target, divergence_threshold, max_batch_diff, speed_hint, partition_ratios, progressive, max_grad_norm, lr_scale_ratio, snapshot_timeout, checkpoint_every, timeline).
- **Auto-bootstrap**: when only `fdl.yml.example` (or `.dist`) is present, `fdl` offers to copy it into the real, gitignored `fdl.yml` so users can customize without polluting the repo.
- **Built-in script targets** (e.g. `fdl test`, `fdl cuda-test-all`, `fdl shell`, `fdl bench`, `fdl self-build`): any unknown command is resolved against the project's `scripts:` map and wrapped in `docker compose run --rm <service>` when a `docker:` field is set. Replaces the old `make` workflow.
- **Sub-command dispatch**: `fdl <cmd> [<job>] [--flag ...]` resolves `<cmd>` against `commands:`, picks the named job (or defaults), merges DDP/training/output sections and forwards everything as CLI flags to the configured `entry`. Pass-through for unknown flags is preserved.
- **Recursive help**: `fdl <cmd> --help` and `fdl <cmd> <job> --help` print resolved options and inherited defaults.

#### CLI: `fdl completions` / `fdl autocomplete`
- **`fdl completions <bash|zsh|fish>`**: emits a shell-completion script that knows about all built-in commands, the local project's `scripts:` and `commands:`, and per-sub-command jobs.
- **`fdl autocomplete`**: dynamic, project-aware completion suggestions for the current cwd.
- Designed to be sourced from `~/.bashrc` / `~/.zshrc` so completions update automatically as `fdl.yml` evolves.

#### CLI: `fdl diagnose --json`
- The diagnostics report now has a fully structured `--json` mode for CI pipelines and tooling: system, CUDA devices, libtorch variants, compatibility verdict.

#### Docs: PyTorch Porting Guide
- **`docs/porting.md`** (257 lines, full rewrite from the previous 7-line stub): user-facing porting guide that mirrors the AI skill (`ai/skills/port/guide.md`) and references `fdl api-ref` for the canonical type/method index.
- **`docs/cli.md`** (130 lines): full CLI reference (setup, libtorch, init, diagnose, api-ref, install, skill, run, completions, config, verbosity flags, fdl.yaml manifest).
- **`docs/design/run-config.md`** (296 lines): formal spec for `fdl.yaml` — schema, merge order, sub-command resolution, Docker integration, and how DDP/training/output map onto `DdpConfig` / `DdpRunConfig`.
- Updates to `docs/pytorch_migration.md` and the CLI section of the README.

#### CLI: API Reference Generator
- **`fdl api-ref`**: Generate a structured API reference from flodl source. Extracts all public types, constructors, methods, builder patterns, trait implementations, and doc examples.
  - Human-readable output (1700+ lines, 170 types) or `--json` for structured data.
  - `--path <dir>` for explicit source path.
  - Auto-discovers source: project checkout, cargo registry, or downloads latest release from GitHub.
  - Downloaded sources cached at `~/.flodl/api-ref-cache/<version>/` for instant re-use.
  - Designed for AI-assisted PyTorch-to-flodl porting: the reference provides everything an agent needs to map PyTorch patterns to flodl equivalents.

#### PyTorch Porting Skill
- **`ai/skills/port/`**: AI-assisted PyTorch-to-flodl porting framework. Universal porting guide (`guide.md`) and agent instructions (`instructions.md`) that work with any AI coding assistant. Covers the full journey from environment setup (`fdl init`) through model translation (FlowBuilder patterns, layer mapping, loss/optimizer/scheduler tables) to validation (`cargo check` loop).
- **`ai/adapters/claude/`**: Claude Code adapter (SKILL.md template) for `/port` slash command. Installed via `fdl skill install`.
- Guide includes: project scaffolding (native vs Docker), 30+ module mappings, FlowBuilder patterns (sequential, residual, skip connections, split/merge, loops, tags), training loop translation, data loading, checkpointing, device management, and Rust-specific idioms.

#### CLI: Global Install & Self-Update
- **`fdl install`**: Copy the current binary to `~/.local/bin/fdl` for global access. Downloads the latest release from GitHub if a newer version is available. Detects shell (bash/zsh) and prints PATH instructions if needed.
- **`fdl install --dev`**: Symlink to the current binary instead of copying. Global `fdl` tracks local builds automatically. Every `cargo build --release -p flodl-cli` updates the global command instantly. Ideal for developers.
- **`fdl install --check`**: Compare installed version against latest GitHub release. Shows install mode (dev symlink or copied binary).
- Version-aware: shows "Updating 0.3.0 -> 0.3.1" or "already installed".
- Platform detection for pre-compiled binaries (linux/darwin/windows, x86_64/aarch64/arm64).

#### CLI: Skill Management
- **`fdl skill install`**: Detect the user's AI coding tool (Claude Code, Cursor) and install flodl skills. Auto-detects `.claude/` or `.cursorrules`. Copies universal skill files (guide, instructions) plus tool-specific adapter. `--tool <name>` to force a tool, `--skill <name>` to install one skill.
- **`fdl skill list`**: Show available skills and detected tools with install status.
- Claude Code: installs `/port` slash command to `.claude/skills/port/`.
- Cursor: appends porting context to `.cursorrules`.
- Skill files embedded in the binary via `include_str!`, so it works without a repo checkout.
- Re-running `fdl skill install` updates existing skills in place.

### Changed

#### DDP — Streaming Epochs and NCCL Cadence Boundaries
- **Streaming epoch dispatch**: `Coordinator::dispatch_next_chunk` now streams sub-epoch chunks instead of full-epoch partitions in `Cadence` and `Async` modes, adapting to live throughput. Added a guard so the coordinator never recreates chunk pools for already-aggregated epochs (was causing a deadlock under heterogeneous cadences).
- **NCCL cadence boundary fixes**: per-rank epoch ack handling rewritten so that the slowest rank no longer stalls the next epoch's `SyncNow` broadcast. ElChe anchor + overshoot remain anchored to the slow rank's wall time.
- **`max_overshoot` is Async-only**: documented as such; the auto-tune is no longer evaluated for `Cadence`.
- **Convergence safety net**: divergence signals now reset after every NCCL averaging event (was leaking stale norms across intervals and pinning the anchor at 1).

#### Optimizer Module Layout
- **`flodl/src/nn/optim.rs` (1975 lines) split into a module**: `optim/{mod, sgd, adam, rmsprop, adagrad, radam, nadam}.rs`. Public API and behavior unchanged; navigation and review surface dramatically improved.

#### FFI Shim Layout
- **`flodl-sys/shim.cpp` (4517 lines) split into themed translation units**: `ops_tensor.cpp`, `ops_nn.cpp`, `ops_math_ext.cpp`, `ops_training.cpp`, `ops_cuda.cpp`, plus a shared `helpers.h`. `shim.cpp` is now a unity-build aggregator. No FFI surface change.

#### Other
- **Rust doc warnings**: Fixed all 32 documentation link warnings (unresolved cross-module references, private item links).
- **GitHub Actions**: Added `FORCE_JAVASCRIPT_ACTIONS_TO_NODE24` env to silence Node.js 20 deprecation warnings.
- **Release workflow**: `gh release create` now falls back to `gh release upload --clobber` when the release already exists (tag push before workflow completes).
- **CLI help text**: Updated to reflect broader scope (API reference, global install). Added examples for `api-ref` and `install` commands.

### Fixed

#### CPU Averaging Race Condition
- **`snapshot_params()` stream sync**: Added `comm_stream.synchronize()` before reading GPU parameters for CPU averaging snapshots. Without this, `Update` + `RequestParams` messages processed in the same `handle_control()` call could read mid-copy GPU memory from a pending `load_averaged()` non-blocking transfer. The coordinator's `tick()` method can send both messages in the same tick when averaging completes and the next cycle triggers immediately.
- **CPU averaging convergence fixed**: The stream sync fix (above) resolved the CPU averaging convergence failure from 0.3.0. All three CPU policies (Sync/Cadence/Async) now converge correctly (91-92% on CIFAR-10 ResNet-20, matching NCCL). Both backends are production-ready.

#### Test Stability
- **`test_graph_loop_leak`**: removed quantitative assertions (`live_tensor_count`, RSS) that flake under parallel CI. The test's real value is exercising 500 iterations of graph+loop+optimizer without crashing (use-after-free, double-free, unbounded Rc chains). Diagnostics are logged for manual review.
- **NCCL/Graph distribute test isolation**: clarified ignore set so `fdl cuda-test-nccl` covers both `nccl` and `graph_distribute` patterns and `fdl cuda-test-serial` covers everything else.

#### libtorch `AccumulateGrad` Stream Mismatch (DDP Workers)
- **Warning eliminated**: `"AccumulateGrad node's stream does not match"` fired on every DDP backward pass when workers ran on a non-default training stream. Three stacked undocumented libtorch facts combined to produce it, and fixing any one of them alone was insufficient:
  1. `AccumulateGrad` nodes capture their stream into `input_metadata` at **construction time**, not at each runtime backward call.
  2. The node is created lazily on first `backward()` **inside the autograd engine's worker thread**, whose current stream is the device default (not the user's training stream).
  3. `AutogradMeta` holds a `weak_ptr` to the node, so without an external strong reference it is collected between iterations and re-created on the default stream on every backward pass.
- **`Tensor::ensure_grad_accumulator()`** (`flodl/src/tensor/mod.rs`) / **`Variable::ensure_grad_accumulator()`** (`flodl/src/autograd/variable.rs`): eagerly materialize the `AccumulateGrad` node for a leaf tensor with `requires_grad=true`, pinning its stream to the current CUDA stream at the moment of the call. Returns a `GradAccumulatorHandle` that keeps the node alive through a strong `shared_ptr<Node>` on the C++ side. No-op for non-leaf or non-`requires_grad` tensors.
- **`GradAccumulatorHandle`** (`flodl/src/tensor/mod.rs`): opaque `Send + Sync` strong-reference handle. `Drop` frees the node (unless a backward pass still holds its own reference). Intended to be held for the lifetime of the owner, typically a DDP worker.
- **FFI additions** (`flodl-sys/ops_training.cpp`, `shim.h`, `src/lib.rs`): `flodl_ensure_grad_accumulator(FlodlTensor, void**)` and `flodl_grad_accumulator_delete(void*)`. The C++ side calls the semi-internal libtorch API `torch::autograd::impl::grad_accumulator()` (found by reading libtorch source) and heap-allocates the returned `shared_ptr<Node>` so Rust owns its lifetime.
- **`GpuWorker` construction reordered** (`flodl/src/distributed/ddp_run/worker.rs`): CUDA streams are now created **before** `model_factory` so every leaf tensor (parameters, buffers, initial copies, optimizer state, `AccumulateGrad` nodes) is allocated under `StreamGuard(compute_stream)` and carries the training-stream affinity from birth. New `_grad_accumulators: Vec<GradAccumulatorHandle>` field on `GpuWorker` holds strong references to every parameter's accumulator for the worker's lifetime; explicitly documented as liveness-only ownership (never read at runtime, dropping it re-introduces the bug).
- **Validated**: 54 training runs across 6 architectures (`logistic`, `mlp`, `lenet`, `char-rnn`, `gpt-nano`, `conv-ae`) times 9 DDP modes with zero warnings in any `training.log`. Also validated across the earlier 6-mode 200-epoch `resnet_graph` run on CIFAR-10.
- **Side effect**: unblocks CUDA Graph capture for DDP workers. Graph capture fails loudly on stream mismatches between the training stream and the accumulator stream, so prior workarounds are no longer needed.

## [0.3.0] - 2026-04-08 — Multi-GPU & Infrastructure

### Added

#### Async GPU-CPU Foundation
- **`CudaEvent`**: Record/synchronize/elapsed_time on CUDA streams. `CudaEventFlags` (Default for timing, DisableTiming for pure sync). RAII Drop, Send. 14 FFI functions (7 event + 7 stream).
- **`CudaStream`**: Pool-managed streams per device. Synchronize, wait_event, is_complete. RAII Drop, Send.
- **`StreamGuard`**: RAII stream switching (sets on create, restores default on drop). Async copy pattern: `let _guard = StreamGuard::new(&stream); tensor.to_device_async(Device::CPU)?;`
- Enables zero-stall GPU-to-CPU pipeline: `training stream -> CudaEvent -> copy stream -> CPU`

#### NCCL Collective Operations
- **`NcclComms`**: RAII communicator group for multi-GPU collectives. 5 FFI functions wrapping raw NCCL (ncclCommInitAll, AllReduce, Broadcast via GroupStart/End).
- **`ReduceOp`**: Sum, Prod, Max, Min, Avg.
- **`all_reduce()`** / **`all_reduce_on_streams()`**: In-place AllReduce across all devices (default or explicit streams).
- **`broadcast()`** / **`broadcast_on_streams()`**: Broadcast from root rank to all devices.
- Raw NCCL (not c10d) for minimal overhead in single-process multi-GPU.

#### NCCL Per-Rank Communication
- **`NcclRankComm`**: Per-rank communicator for multi-threaded DDP. Each GPU thread owns one comm, runs collectives independently. `Send` so it can be moved into spawned threads.
  - `init_rank(rank, world_size, &uid)`: Direct per-rank init from a shared `NcclUniqueId`.
  - `all_reduce(&[&Tensor], ReduceOp)` / `all_reduce_on_stream(...)`: Rank-local AllReduce.
  - `broadcast(&[&Tensor], root)`: Rank-local broadcast.
- **`NcclComms::split()`**: Extracts per-rank `NcclRankComm` from a group-initialized `NcclComms`. Preferred over per-thread `init_rank` because `ncclCommInitRank` from worker threads corrupts CUDA context on heterogeneous GPUs. Init-on-main + split is the safe pattern.
- **`NcclAbortHandle`**: Arc-shared handle to abort a stuck `NcclRankComm`. Calling `abort()` unblocks any thread stuck in an AllReduce/Broadcast and makes the comm's Drop a no-op. Used by `DdpHandle` to recover from worker death without deadlocking surviving workers.
- **`NcclUniqueId`**: 128-byte unique ID for coordinating per-rank init. `NcclUniqueId::new()` generates on rank 0, then shared to all ranks.
- 7 per-rank FFI functions: `flodl_nccl_get_unique_id`, `flodl_nccl_init_rank`, `flodl_nccl_destroy_rank`, `flodl_nccl_all_reduce_rank`, `flodl_nccl_abort_rank`, `flodl_nccl_split_rank`.

#### Transparent Multi-GPU Training
- **`Graph::distribute()`**: Auto-detect GPUs, create replicas, broadcast params. Single line to enable multi-GPU. No-op on single GPU.
- **`Graph::set_optimizer()`**: Creates per-replica optimizers when distributed.
- **`Graph::step()`**: AllReduce gradients + sync buffers + optimizer step + zero_grad. One call replaces the manual loop.
- **`Graph::set_lr()`** / **`world_size()`** / **`is_distributed()`**: Multi-GPU aware API.
- **Cross-device autograd**: `Tensor::to_device()` preserves grad_fn (ToCopyBackward). Forward chunks input, forwards shards on their GPUs, gathers via to_device + cat. libtorch autograd naturally flows gradients back through device transfers.
- **`Ddp`**: Manual DDP coordinator for complex training patterns (GAN, RL, progressive). Explicit sync_params, all_reduce_gradients, sync_buffers.
- Training loop is identical for 1 or N GPUs; `distribute()` is the only difference.

#### Async Data Loading Pipeline
- **`DataSet` trait**: Per-item dataset (`get(index) -> Vec<Tensor>`). `Send + Sync` for background prefetch. Automatic batching via `DataSetAdapter` (pre-allocate + copy, O(1 sample) peak memory).
- **`BatchDataSet` trait**: Per-batch dataset (`get_batch(indices) -> Vec<Tensor>`) for bulk-efficient sources (mmap, database). `Send + Sync`.
- **`Sampler` trait**: Index ordering per epoch. Built-in: `RandomSampler` (deterministic per seed+epoch), `SequentialSampler`.
- **`Batch`**: Named tensor wrapper with `Index<usize>` and `Index<&str>` for clean destructuring (`let images = &b["image"]` or `&b[0]`). `.names()`, `.has()`, `.get_named()` for introspection. Owns its tensors.
- **`DataLoader`**: Builder pattern with auto-detection of resident vs streaming mode.
  - **Resident mode**: Dataset fits in VRAM (75% headroom). Loaded once via `pin_memory()` + `to_device()`. Per-epoch: GPU-side `index_select` with shuffled permutation. Zero CPU-GPU transfer after warmup.
  - **Streaming mode**: Persistent worker thread with dedicated `CudaStream`. Per-epoch fresh batch channel (no deadlock on mid-epoch drop). Worker: `get_batch` -> `pin_memory` -> `StreamGuard` + `to_device_async` -> `CudaEvent`. Consumer: `event.synchronize()` (typically instant due to prefetch depth).
  - **CUDA OOM fallback**: If resident load fails with OOM, automatically retries with streaming mode.
  - **Auto prefetch depth**: `clamp(free_vram * 10% / batch_bytes, 2, 4)`. Override with `.prefetch(n)` for high-latency cloud/NFS storage.
  - `.streaming()` to force streaming mode (preserve VRAM headroom, benchmarking).
  - `drop_last` defaults to `true` (BatchNorm safety: size-1 batches cause NaN variance).
  - `EpochIterator` implements `Iterator<Item = Result<Batch>>` + `ExactSizeIterator`.
- **`TensorError::is_cuda_oom()`**: Detect CUDA out-of-memory errors for graceful fallback.
- **`.names()`**: Builder method for named batch fields (`["image", "letter", "case", "origin"]`). Auto-generated positional names ("0", "1", ...) when unspecified. Validates name count against dataset tensor count.
- DDP-aware: loader yields pinned CPU data, `forward_distributed` scatters to devices efficiently.

#### Resident DDP
- **DDP-aware DataLoader**: Third internal mode `DistributedLoader` with per-device backends. Each GPU independently selects resident (data fits in VRAM) or streaming (prefetch worker) based on its own VRAM. No lowest-common-denominator constraint.
- **`DeviceBackend`**: Per-device data strategy. Resident: full dataset on GPU, index_select per batch. Streaming: dedicated PrefetchWorker with async H2D transfers.
- **`Graph::set_data_loader(loader, "input")`**: Attach DataLoader to model. When distributed: upgrades to per-device backends. Auto-wires batch names to graph `.input()` ports. Remaining names treated as targets for loss.
- **`Graph::epoch(epoch)`**: Returns `GraphEpochIterator` that produces per-rank shards and user-facing Batch. When distributed: each backend produces on-device data, shards stored for presharded forward. When single-GPU: delegates to DataLoader.
- **`Graph::forward_batch(&batch)`**: Batch-aware forward. Extracts named inputs, handles DDP presharding transparently. Coexists with `Module::forward(&Variable)`.
- **Presharded forward path**: `forward_distributed_presharded()` consumes per-rank shards from DataLoader via `.take_shards()`. Each replica forwards its local shard (zero cross-device input transfer). Outputs gathered to gather device. CudaEvent timing for auto-balancer.
- **Multi-input auto-wiring**: `set_data_loader()` precomputes `shard_input_map` matching graph `.input()` port names to batch tensor positions. `forward_distributed_presharded()` passes all inputs (primary + auxiliary) to each replica via `as_graph().forward_impl()`. Single-GPU `forward_batch()` also builds the full input vector. Enables multi-input models (FBRL with case/origin alongside image) in distributed training.
- **Efficient distributed streaming**: `StartDistributedEpoch` + `LoadBatch` worker commands. One channel per epoch instead of per-batch channel creation. Flat state machine in `worker_loop` (no nested loops). `PrefetchWorker::start_distributed_epoch()` opens the channel once, `load_batch()` sends indices per batch.
- **Gather device selection**: Prefers resident backend with most free VRAM. Falls back to CPU if all backends are streaming (targets fetched from dataset). No GPU 0 priority.
- **Auto-balancing integration**: Epoch iterator reads chunk_ratios fresh per batch. Shard sizes adapt as ratios change every 50 steps. Mixed resident/streaming backends handle dynamic ratios correctly.
- Training loop identical for 1 or N GPUs. `distribute()` + `set_data_loader()` are the only differences.

#### `Ddp::setup()` — One-Liner DDP Setup
- **`Ddp::setup(&model, builder, optimizer)`**: Single call to auto-detect GPUs, distribute the model, set per-replica optimizers, and enable training mode. No-op distribute for single GPU/CPU (still sets optimizer + training). Training loop identical for 1 or N GPUs.
- **`Ddp::setup_with(&model, builder, optimizer, config)`**: Same as `setup()` but accepts a `DdpConfig` for explicit El Che configuration (speed hints, overhead target, max anchor).
- **`Ddp::is_heterogeneous()`**: Detects mixed GPU models. `setup()` auto-enables El Che when heterogeneous GPUs are detected.
- **Hardware diagnostics**: Always prints detected hardware to stderr on call:
  - `ddp: 2 GPUs (heterogeneous) | RTX 5060 Ti (16.0 GB) | GTX 1060 (6.0 GB)`
  - `ddp: 1 GPU | RTX 5060 Ti (16.0 GB) | single-device mode`
  - `ddp: no CUDA available | CPU mode`

#### Multi-GPU Dashboard
- **Per-GPU tabs**: Tab bar appears when 2+ GPUs detected (hidden for single-GPU, zero visual regression). Each GPU tab shows 4 time-series charts: VRAM usage (bytes, with physical limit reference line), utilization (%), throughput (samples/ms), batch share (%).
- **GPU Overview card** (Home tab): Compact row per GPU with VRAM bar, utilization, throughput, and batch share. Fastest GPU highlighted green, slowest yellow.
- **JS data model**: `gpuSeries[deviceIndex]` with per-device VRAM, throughput, chunk, and utilization arrays. Populated from `d.gpus` in `processEpoch()`. Works in both live SSE and archive replay modes.

#### Multi-GPU Dashboard Data Pipeline
- **`GpuSnapshot`**: Per-device resource sampling (VRAM allocated/total, utilization, device name). `ResourceSampler` iterates all CUDA devices on each sample. Aggregate fields kept for backward compat with single-GPU dashboards.
- **`GpuMetrics`**: DDP metrics per device (EMA throughput, chunk_ratio, shard_size). Exposed via `Metrics::gpu_metrics()` trait method with default empty impl.
- **Per-GPU JSON in epoch records**: `"gpus":[...]` array merges hardware snapshots (from `GpuSnapshot`) with DDP metrics (from `GpuMetrics`). Flows through SSE live updates and HTML archives.
- **`Graph::auto_distribute()`**: Auto-detect usable CUDA devices and distribute. No-op on single GPU. Keeps the builder closure for user-controlled model construction.
- **`Graph::shard_sizes()`** / **`Graph::devices()`**: Public accessors for per-rank shard sizes and device list.

#### Auto-Balancing
- **Per-GPU throughput measurement**: CudaEvent-based timing around each replica's forward pass in `forward_distributed()`. Zero overhead (async GPU recording, no CPU sync).
- **EMA throughput tracking**: Exponentially smoothed samples/ms per device (alpha=0.3). First measurement initializes directly, subsequent measurements blend.
- **Adaptive batch sharding**: After 10 calibration steps with equal splits, `chunk_ratios` are recomputed proportional to measured throughput. Re-evaluated every 50 steps. `MIN_CHUNK_RATIO` (5%) prevents starving any GPU.
- **Weighted gradient averaging**: When chunk ratios are unequal, each replica's gradient is scaled by `(shard_size / batch_size)` then AllReduce Sum, producing the mathematically correct mean gradient regardless of shard distribution.
- **`Graph::chunk_ratios()`**: Query current batch distribution ratios (for logging/debugging).
- **`Graph::throughput()`**: Query per-device EMA throughput (samples/ms).
- All auto-balancing is internal to `forward_distributed()` and `step()`. Training loop is unchanged.

#### NCCL Device Safety
- **Device save/restore**: All `NcclComms` methods (`new`, `all_reduce`, `broadcast`, and stream variants) now save and restore the current CUDA device around FFI calls. Prevents NCCL operations from leaking device context changes to callers.
- **Shared `NCCL_LOCK`**: Single `pub(crate)` mutex in `ddp` module, used by both `nccl::tests` and `ddp::tests` to serialize NCCL communicator operations.

#### El Che — Heterogeneous DDP
- **`ElChe`**: Cadence strategy for mixed-GPU training. Slow device anchors the sync cadence, fast devices range ahead processing more batches per sync. Named after Che Guevara's marching principle: "the column marches at the slowest one's pace."
  - `ElChe::new(world_size, anchor)` with builder pattern.
  - `with_speed_ratio(slow_rank, ratio)`: Seed initial batch distribution from known speed differential. Self-corrects after first `report_timing()`.
  - `with_overhead_target(f64)`: Default 0.10 (10%). Auto-tunes anchor upward to keep AllReduce overhead below target.
  - `with_max_anchor(usize)`: Gradient staleness cap. Prevents unbounded accumulation.
  - `report_timing(&wall_ms, sync_ms)`: Discovers true speed ratios from CudaEvent measurements, recomputes batch counts, auto-tunes anchor.
  - `batch_counts() -> &[usize]`: Per-device batch counts for the current cadence step.
  - `clamp_total(max) -> Vec<usize>`: Proportional clamping for epoch-end alignment.
- **`DdpConfig`**: Configuration struct for `Ddp::setup_with()`.
  - `speed_hint(slow_rank, ratio)`: Initial speed estimate (optional, self-corrects).
  - `overhead_target(f64)`: AllReduce overhead ceiling.
  - `max_anchor(Option<usize>)`: `None` = auto (default), `Some(0)` = disable El Che (traditional DDP), `Some(n)` = fixed cap.
  - `max_grad_norm(f64)`: Per-rank gradient clipping before normalize-by-count and weighted AllReduce. Bounds accumulated gradients on all ranks (including replicas the caller cannot reach). Uses fused C++ kernel (`clip_grad_norm_fused`).
- **`Graph::step()` El Che branch**: Normalizes accumulated gradients by `1/count[rank]` (mean per device), weighted AllReduce by `count[rank]/total` (proportional contribution), reports timing to ElChe for adaptation. Per-rank gradient clipping when configured. Existing scatter and single-GPU paths unchanged.
- **`Graph::has_el_che()`** / **`Graph::configure_el_che()`**: Query and configure El Che state.
- **`weighted_all_reduce_gradients()`**: Scales each replica's gradient by batch contribution before AllReduce Sum. Produces the mathematically correct mean gradient regardless of per-device batch counts.

#### El Che Forward Path
- **`forward_distributed_el_che()`**: Multi-batch per-device forward. Each device processes `batch_counts[rank]` complete batches independently. Gradients accumulate naturally via libtorch autograd across all forward passes. CudaEvent timing per rank.
- **Tagged output gathering**: After each forward pass, tagged outputs (`Graph::tag()`) are captured from each device and concatenated across all batches and all devices. Custom loss functions work transparently on gathered intermediates: `model.tagged("scan_locations")` returns the catted value from all devices.
- **Loop trace gathering**: Per-step outputs from loop nodes (`trace_buf`) are gathered across all batches and all devices, keyed by `(tag_name, step_index)`. `model.traces("attn")` returns catted per-step traces. Enables transparent El Che training for models with loop-based attention (scan/read fixations, per-step losses). No-op when no loop nodes exist.
- **El Che data routing**: `DistributedEpochIterator` pulls `sum(batch_counts)` complete batches per iteration (not shards). Routes whole batches to each device via `load_batch_on_device()` (supports both Resident index_select and Streaming prefetch worker). Proportional clamping near epoch boundaries.
- **Epoch-end flush**: `ActiveGraphEpochIterator::drop()` detects accumulated un-synced gradients (forward without step) and forces a final `step()` to prevent silent gradient loss.
- **`Graph::epoch()`** seeds initial batch counts from `ElChe::batch_counts()`. **`Graph::step()`** feeds updated counts back to the loader after `report_timing()`.
- Training loop is identical for homogeneous and heterogeneous GPU setups. `Ddp::setup()` detects heterogeneous hardware and enables El Che automatically.

#### DDP Builder — Thread-Per-GPU Training
- **`DdpHandle`**: Thread-per-GPU training with Local SGD and adaptive parameter averaging. Each GPU runs its own training loop with a local optimizer. A lightweight coordinator thread triggers periodic parameter averaging. Two orthogonal knobs: [`ApplyPolicy`] (when to average) and [`AverageBackend`] (how to average).
- **`DdpBuilder`** (recommended entry point): Fluent API for configuring and launching training. Required: `.dataset()`, `.batch_size()`, `.num_epochs()`. Optional: `.policy()`, `.backend()`, `.overhead_target()`, `.max_anchor()`, `.anchor()`, `.divergence_threshold()`, `.max_batch_diff()`, `.checkpoint_every()`, `.checkpoint_fn()`, `.epoch_fn()`, `.progressive_dispatch()`.
  ```rust
  let ddp = Ddp::builder(model_factory, optim_factory, train_fn)
      .dataset(dataset)
      .batch_size(32)
      .num_epochs(10)
      .policy(ApplyPolicy::Cadence)
      .backend(AverageBackend::Nccl)
      .run()?;
  let state = ddp.join()?;
  ```
- **`Ddp::builder()`**: Quick-start alternative (replaces the former `AsyncDdp::auto()`/`auto_with()`).
- **`ApplyPolicy`**: Controls WHEN averaging occurs.
  - `Sync`: K=1 (every batch). Equivalent to standard DDP. Best convergence.
  - `Cadence`: K=N (ElChe anchor count). Slow GPU anchors the cadence, fast GPUs fill wall time. Uses wall-time trigger (fires when slowest rank's accumulated wall time reaches anchor wall-time). Recommended for heterogeneous hardware.
  - `Async`: K=adaptive. Uses batch-count trigger (fires when all ranks complete their assigned counts). Overshooting is intentional: each replica explores slightly different parameter neighborhoods between averaging events, producing diversity that benefits convergence. Auto-tunes interval from divergence monitoring. Maximum throughput.
- **`AverageBackend`**: Controls HOW averaging is performed. Orthogonal to policy, all combinations valid for A/B testing.
  - `Nccl`: In-place AllReduce on GPU. Zero extra memory, GPU-to-GPU DMA. All GPUs sync at collective barrier.
  - `Cpu`: Workers send parameter snapshots to coordinator, which averages on CPU and distributes. No GPU ever blocks. Uses O(world_size * model_size) CPU RAM. Non-blocking 3-phase state machine (Idle/Collecting/Computing) keeps coordinator responsive during averaging.
- **`GpuWorker<M>`**: Generic worker bound to a single GPU. Thread-local model + optimizer (Rc-based, not Send). CUDA streams for overlapped compute/communication. Handles `SyncNow` (NCCL), `RequestParams`/`Update` (CPU), `Throttle`, `StartEpoch`, `Checkpoint`, `Shutdown`.
- **`Coordinator`**: Lightweight scheduling thread. Collects timing from workers (for ElChe throughput ratios), triggers averaging, monitors divergence to auto-tune interval, rebalances data partitions. Builder pattern with configurable `divergence_threshold`, `overhead_target`, `max_anchor`, `checkpoint_every`, `snapshot_timeout_secs`.
- **`TrainedState`**: Return type from `DdpHandle::join()`. Contains averaged `params` and `buffers` as CPU tensors, ready for inference or checkpoint.
- **`DdpRunConfig`**: Configuration struct with builder methods: `with_overhead_target()`, `with_max_anchor()`, `with_anchor()`, `with_divergence_threshold()`, `with_max_batch_diff()`, `with_max_grad_norm()`, `with_checkpoint_every()`, `with_snapshot_timeout()`, `with_partition_ratios()`, `with_progressive_dispatch()`.
- **Per-worker gradient clipping**: `DdpBuilder::max_grad_norm(f64)` clips gradients between `backward()` and `optimizer.step()` on each GPU worker. Prevents gradient spikes on any single GPU from propagating through AllReduce averaging. Same fused kernel as El Che path.
- **`progressive_dispatch`**: When enabled, the coordinator streams work in small chunks instead of sending full epoch partitions, adapting to throughput continuously. Default: auto (true for Cadence/Async, false for Sync).
- **Global epoch management**: Coordinator owns epochs globally. Workers are mode-agnostic (wait for `EpochPlan`, run partition, report metrics). `EpochPlan { epoch, partition_offset, partition_size }` ensures deterministic, non-overlapping sample coverage. Throughput-proportional partition sizing when ElChe is calibrated; `partition_ratios` for fixed splits. Auto lookahead in `Async` mode (fast ranks may run 1 epoch ahead).
- **Single-GPU fallback**: With fewer than 2 CUDA devices, training runs on the main thread with no coordinator or averaging. API is identical; `join()` returns `TrainedState` in both cases.

#### DDP Builder — Robustness
- **`max_batch_diff`**: Hard limit on how far any GPU can run ahead of the slowest. Workers that exceed the limit are throttled (block on control channel) until the next averaging event. `Some(0)` = strict lockstep.
- **`drain_until_shutdown`**: After training, workers keep handling control messages (especially `SyncNow`) until the coordinator sends `Shutdown`. Prevents NCCL deadlock when workers finish at different times.
- **NCCL init-on-main + split()**: All NCCL communicators initialized from the main thread via `NcclComms::new()` then `split()` into per-rank `NcclRankComm`. Per-thread `ncclCommInitRank` corrupts CUDA context on heterogeneous GPUs.
- **NCCL abort handles**: If a worker dies mid-collective, `DdpHandle::abort_nccl()` calls `ncclCommAbort` on all communicators, unblocking surviving workers. Also triggered in `Drop`.
- **Worker error propagation**: Failed workers set the shared shutdown flag and send `TimingMsg::Exiting` so the coordinator stops including that rank in collectives.
- **CPU averaging timeout**: Configurable `snapshot_timeout_secs` (default 5s). If not all worker snapshots arrive in time, the round is soft-aborted (logged with missing rank IDs and abort count), stale snapshots drained, and retried on the next cycle.
- **CPU Update delivery logging**: Failed Update deliveries to dead workers are logged with the affected rank.
- **Shutdown cleanup**: `drain_avg_state()` logs and joins any in-progress CPU averaging (Collecting or Computing) before the coordinator exits, preventing detached threads from holding GPU resources.

#### DDP Builder — Observability
- **Averaging success logging**: Both paths log on successful averaging. NCCL: `"NCCL averaging #N complete (vV)"`. CPU: `"CPU averaging #N complete (vV, X.Xms)"` with timing.
- **Per-rank epoch metrics**: Worker epoch-end metrics (rank, epoch, loss, batches, wall time) forwarded to stderr from the coordinator loop.
- **Coordinator accessors**: `avg_count()`, `abort_count()`, `last_batch_ms()`, `last_avg_ms()`, `is_cpu_averaging()`, `version()`, `avg_interval()`, `is_calibrated()`, `steps_since_avg()` for external monitoring.
- **Divergence monitoring** (Async policy): Per-rank parameter L2 norms tracked. Relative norm difference triggers interval halving (diverging) or doubling (converging). Threshold configurable via `divergence_threshold` (default 0.05).
- **Hardware summary**: Prints GPU count, heterogeneous/homogeneous detection, per-GPU name + VRAM, policy, and backend at launch.

#### DDP Builder — Metrics Pipeline
- **`record_scalar(name, value)`**: Thread-local function callable from inside the train function. Records named scalar metrics (accuracy, custom losses, etc.) per batch. Metrics are aggregated per rank per epoch and forwarded to the coordinator.
- **`EpochMetrics`**: Aggregated metrics for one completed epoch. Fields: `epoch`, `avg_loss`, `batches_processed`, `epoch_ms`, `samples_processed`, `per_rank_loss`, `per_rank_time_ms`, `per_rank_scalars`, `scalars`.
- **`DdpHandle::poll_metrics()`**: Non-blocking poll for completed epoch metrics. Returns a `Vec<EpochMetrics>` of all epochs aggregated since the last poll. Enables external monitoring loops.
- **`DdpHandle::next_metrics()`**: Blocking call that returns the next available `EpochMetrics`. Useful for sequential metric processing.
- **`DdpHandle::setup_monitor(&self, &mut Monitor)`**: Wire the DDP handle's graph identity, architecture SVG, and training config into a training monitor. Enables the live dashboard and HTML archive for DDP Builder training runs.
- **`LossContext`**: Per-batch context passed to loss closures in distributed training. Provides batch metadata (shard sizes, device indices) for loss functions that need to weight contributions correctly.

#### DDP Builder — Epoch Callback
- **`EpochFn<M>`**: `Arc<dyn Fn(usize, &mut GpuWorker<M>) + Send + Sync>`. Called at the start of each epoch inside each worker thread, before `run_epoch_plan()`.
- **`.epoch_fn()`** on `DdpBuilder`: Set the callback. Typical uses: LR schedules, noise curricula, dynamic loss weights.
- **`GpuWorker::set_lr(f64)`**: Delegate to the worker's optimizer.
- **`GpuWorker::current_epoch()`**: Public accessor for the current epoch number.

#### DDP Builder — Checkpointing
- **`CheckpointFn<M>`**: `Arc<dyn Fn(u64, &M) -> Result<()> + Send + Sync>`. Called on rank 0 after averaging events (multi-GPU) or epoch boundaries (single-GPU). Errors are logged but do not stop training.
- **`checkpoint_every(n)`**: Save every N averaging events. Coordinated through `ControlMsg::Checkpoint` to rank 0's worker thread (which owns the model).
- **`TrainedState`** on partial failure: If some workers died, `collect_final_state()` averages surviving workers' snapshots. If averaging fails, falls back to the first snapshot's tensors. Returns `None` only if zero snapshots arrived.

#### Adaptive Data Pipeline
- **VRAM-aware prefetch depth**: `prefetch_depth_from_vram()` computes prefetch budget as the gap between current VRAM usage and a configurable cap. No manual tuning needed.
- **Bootstrap prefetch**: Initial depth of 4 batches during DataLoader construction. Real depth computed at `epoch(0)` after model is loaded and VRAM usage is stable.
- **Per-epoch VRAM probing**: `epoch(N)` re-probes VRAM usage and fills up to the cap. Adapts to VRAM fragmentation and activation memory changes across epochs.
- **`DataLoaderBuilder::vram_max_usage(f64)`**: Default 0.90 (use up to 90% of total VRAM). Clamped to [0.50, 0.99]. Remaining headroom covers activations, gradients, and CUDA overhead.
- **Manual override**: `.prefetch(n)` or `set_prefetch_depth()` disables automatic adaptation (`user_set_depth` flag).
- **`auto_resize()`**: Manual trigger for VRAM-based resize between epochs.

#### Module Builders
- **`ConvTranspose1dBuilder`**, **`ConvTranspose2dBuilder`**, **`ConvTranspose3dBuilder`**: Fluent builder APIs for transposed convolution layers (`with_stride`, `with_padding`, `with_output_padding`, `with_dilation`, `with_groups`, `with_bias`, `on_device`, `done`). Consistent with existing Conv1d/Conv2d/Conv3d builder pattern.

#### CLI Tool
- **`fdl`** (shell script): Zero-dependency entry point. Auto-detects libtorch, Docker, Rust, GPUs. Dispatches to the compiled binary (native or Docker) with shell fallback for diagnostics. Interactive setup wizard guides users through libtorch installation and build environment selection.
- **`flodl-cli`** (`cargo install flodl-cli`): Standalone Rust binary. Pure Rust, no libtorch dependency. Works inside floDl projects and standalone (system-wide libtorch management under `~/.flodl/`). Override global root with `$FLODL_HOME`. Commands:
  - `fdl setup`: Guided wizard. Detects project vs standalone mode. In a project: system detection, libtorch download, Docker image build. Standalone: system detection, libtorch download to `~/.flodl/`, prints shell export instructions.
  - `fdl libtorch download [--cpu | --cuda 12.6|12.8]`: Auto-detect GPUs and download matching libtorch variant. Project-local or global depending on context.
  - `fdl libtorch build [--docker | --native] [--archs "6.1;12.0"]`: Compile libtorch from source for custom GPU architectures.
  - `fdl libtorch list / info / activate / remove`: Manage installed variants.
  - `fdl init <name> [--docker]`: Scaffold a new floDl project. Default mode uses mounted libtorch (like the main repo). `--docker` bakes libtorch into the Docker image for standalone deployment. Generates Cargo.toml, Dockerfiles, docker-compose.yml, Makefile, and annotated src/main.rs.
  - `fdl diagnose [--json]`: System + GPU + libtorch + compatibility report. Shows context mode (project/global). Probes GPUs via nvidia-smi, verifies libtorch arch coverage, detects Docker containers.
  - `fdl help / version`
- Pre-compiled binaries published via GitHub Releases for Linux x86_64/aarch64, macOS arm64, Windows x86_64. Downloaded automatically by the `fdl` shell script on first use.

#### Small Additions
- **`Linear::no_bias_on_device()`**: Create a bias-free linear layer on a specific device. Previously `no_bias()` was CPU-only.
- **`AdamBuilder::betas()` / `.eps()`**: Customize beta1, beta2, and epsilon in Adam per-group builder. Previously hardcoded to (0.9, 0.999) and 1e-8.
- **`AdamWBuilder::betas()` / `.eps()`**: Same for AdamW per-group builder.
- Improved doc comments on all loss functions (dtype requirements), conv builders, and optimizer constructors.

### Changed

#### Unified DDP API
- **`Ddp` is now the single entry point** for all multi-GPU training modes: `setup()` (user owns the loop), `builder()` (framework owns the loop), `wrap()` (manual).
- **Renamed**: `AsyncDdp` -> `DdpHandle`, `AsyncDdpBuilder` -> `DdpBuilder`, `AsyncDdpConfig` -> `DdpRunConfig`, `Ddp::auto()` -> `Ddp::setup()`, `Ddp::auto_with()` -> `Ddp::setup_with()`.
- **Module renamed**: `nn::async_ddp` -> `nn::ddp_run`.
- **Log prefix**: `async-ddp:` -> `ddp:` in all runtime output.
- **Deprecated aliases** preserved for backward compatibility: `AsyncDdp`, `AsyncDdpBuilder`, `AsyncDdpConfig`, `Ddp::auto()`, `Ddp::auto_with()`.

#### Unified libtorch Management
- **`libtorch/` directory**: Single host-side directory for all libtorch variants.
  - `libtorch/precompiled/cpu|cu128|cu126/` for downloaded pre-built variants
  - `libtorch/builds/<arch>/` for source-compiled variants (e.g., `sm61-sm120`)
  - `libtorch/.active` points to the variant in use
  - `libtorch/<variant>/.arch` contains metadata (cuda version, torch version, architectures, source type)
- **Docker images are libtorch-agnostic**: No libtorch baked into images. Mounted at runtime via volume.
  - `Dockerfile` (new, replaces `Dockerfile.cpu`): Ubuntu + Rust, no libtorch
  - `Dockerfile.cuda`: parameterized `CUDA_VERSION`, cudnn-devel base, no libtorch
  - `Dockerfile.cuda.source`: builder-only (no Stage 2 runtime image), Makefile extracts via `docker cp`
  - `Dockerfile.bench`: removed libtorch download, kept Python + PyTorch pip install
- **docker-compose.yml simplified**: 5 services reduced to 3 (`dev`, `cuda`, `bench`). Removed `cuda-local` and `cuda-source`. All services mount `${LIBTORCH_HOST_PATH}:/usr/local/libtorch:ro`.
- **Makefile auto-detection**: Reads `libtorch/.active` and `.arch` to derive `CUDA_VERSION` and libtorch mount path. Override: `CUDA_VERSION=12.6.0 make cuda-test`.
- **`download-libtorch.sh --project`**: Downloads to `libtorch/precompiled/<variant>/`, writes `.arch` and `.active`. Existing `--path` mode for native installs unchanged.

#### Test Infrastructure
- **15 tests un-ignored**: `cuda_event` (3), `cuda_stream` (4), DDP cross-device autograd (2) tests now run in the normal `make cuda-test` flow. They have proper mutex serialization and early-return guards.
- **NCCL/DDP/Graph tests remain `#[ignore]`**: NCCL communicator init corrupts concurrent CUBLAS operations. Must run single-threaded.
- **Process-isolated test targets**: NCCL tests run in their own cargo process to prevent CUBLAS context poisoning. Fixes SIGABRT in `test_manual_seed_reproducible` when run after NCCL init.
  - **`make cuda-test-all`**: Three-pass target -- parallel + NCCL (isolated) + remaining serial.
  - **`make cuda-test-nccl`**: NCCL/DDP tests only (isolated processes).
  - **`make cuda-test-serial`** (new): Remaining serial tests (CUDA Graphs, manual_seed, probes).

#### Build Targets
- **`make setup`**: Auto-detect hardware, download CPU libtorch + CUDA libtorch (or build from source), build Docker image. One command from zero to ready.
- **`make build-libtorch`**: Compile libtorch from source, extract to `libtorch/builds/<arch>/`, write `.arch`/`.active`.
- **`make cli`** / **`make cuda-cli`**: Build flodl-cli (CPU/CUDA). **`make run-cli`** / **`make cuda-run-cli`**: Run inside Docker.
- **CI updated**: CUDA job downloads libtorch separately and mounts into container (no longer baked into image).

### Removed
- `Dockerfile.cpu` (replaced by `Dockerfile`)
- `cuda-local` and `cuda-source` docker-compose services

## [0.2.2] - 2026-03-31

### Added
- `Tensor::nbytes()` — total size in bytes (`numel() * element_size()`), matches `torch.Tensor.nbytes`

#### Fused sequence RNN kernels
- **`LSTM::forward_seq`** now calls `at::lstm()` — single cuDNN kernel for the entire sequence across all layers, replacing per-timestep cell unrolling. Eliminates N×L kernel launches (N=timesteps, L=layers) per forward pass.
- **`GRU::forward_seq`** now calls `at::gru()` — same fused optimization. Also eliminates the cuDNN benchmark variance that caused ±270ms σ in per-cell dispatch.
- **`flatten_rnn_params`** (shim) — packs per-cell RNN weight tensors into cuDNN's expected contiguous layout using `at::_cudnn_rnn_flatten_weight`, the same function PyTorch's `nn.LSTM.flatten_parameters()` uses internally. Eliminates the "RNN module weights are not part of single contiguous chunk" warning on CUDA. Uses `set_()` under `NoGradGuard` to redirect parameter storage in-place — persists across training steps, self-corrects after checkpoint load or dtype cast.
- **Flatten cache** — LSTM and GRU cache the flattened param tensors after the first forward call, skipping both the per-forward param collection (8 tensors via `flat_map` + `collect`) and the cuDNN flatten FFI call on subsequent forwards. Same strategy as PyTorch's `flatten_parameters()` but without the pointer-validation overhead.
- **`RnnParams` C++ cache** — persistent `std::vector<at::Tensor>` on the C++ side behind an opaque handle (`flodl_rnn_params_create` / `flodl_lstm_cached` / `flodl_gru_cached`). After the first forward, subsequent calls pass a single pointer to the pre-built param vector, eliminating per-forward handle collection, FFI array marshalling, and `std::vector` reconstruction. Matches PyTorch's single-call `at::lstm()`/`at::gru()` pattern exactly.
- FFI chain: `flodl_lstm` / `flodl_gru` in shim → `Tensor::lstm_seq` / `Tensor::gru_seq` in nn_ops (new `flatten` flag skips redundant flatten calls). Cached path: `flodl_lstm_cached` / `flodl_gru_cached` → `Tensor::lstm_seq_cached` / `Tensor::gru_seq_cached`.
- `LSTMCell::forward_step` and `GRUCell::forward_step` unchanged — still available for single-step / streaming use cases

#### Benchmark suite extensions
- **`transformer`** benchmark — 4-layer encoder (MultiheadAttention + FFN + LayerNorm + residual), Embedding, cross-entropy loss. B=32, seq=128, d_model=512, 8 heads.
- **`lstm_seq`** benchmark — 2-layer LSTM + linear projection, directly comparable to gru_seq. B=128, seq=50.
- **`conv_autoenc`** benchmark — Conv2d encoder + ConvTranspose2d decoder (DCGAN-style), reconstruction with MSE loss. B=64, 64×64 images.

### Changed
- **Benchmark σ uses scaled MAD** — variance column now reports Median Absolute Deviation × 1.4826 (σ-equivalent for normal distributions) instead of standard deviation. Robust to OS scheduling outliers, GC pauses, and WSL2 thermal transients that inflated stdev on long runs (e.g. gru_seq Py σ: ±143 stdev → ±27 MAD).

### Fixed
- **Benchmark report generation**: Fix silent `set -e` exit caused by `[ "$ROUNDS" -gt 1 ] && echo 's'` returning exit code 1 inside command substitution when ROUNDS=1. Reports were never written for single-round runs.
- **Benchmark report rotation**: Previous report is now rotated to `report.YYYY-MM-DD-HH-MM-SS.txt` instead of being overwritten. All rotated reports are gitignored.

## [0.2.1] - 2026-03-29

### Added

#### PyTorch Parity — Tensor Operations
- **Math ops**: `log1p`, `expm1`, `log2`, `log10`, `tan`, `asin`, `acos`, `atan`, `erf`, `erfc`, `trunc`, `frac`, `fmod`, `fmod_tensor`, `remainder`, `remainder_tensor`, `lerp`, `lerp_tensor`, `isclose`, `addmm`, `addcmul`, `addcdiv`, `clamp_min`, `clamp_max`, `selu`, `hardswish`, `hardsigmoid`, `prelu`
- **Reductions**: `prod`, `prod_dim`, `cumsum`, `logsumexp`
- **Shape ops**: `flip`, `roll`, `diagonal`, `movedim`, `tile`, `split`, `unbind`, `contiguous`, `cat_many`, `unsqueeze_many`, `narrow_scatter`, `pad_mode` (constant/reflect/replicate/circular), `meshgrid`
- **NN tensor ops**: `conv1d`, `conv_transpose1d`, `conv3d`, `conv_transpose3d`, `avg_pool2d`, `avg_pool1d`, `max_pool1d`, `adaptive_max_pool2d`, `instance_norm`, `group_norm`, `linear` (fused), `pixel_shuffle`, `pixel_unshuffle`, `bilinear`, `embedding_bag`, `interpolate` (nearest/bilinear/bicubic/trilinear), `im2col`, `col2im`, `bce_loss`, `nll_loss`, `ctc_loss`
- **Comparison/similarity**: `maximum`, `minimum`, `atan2`, `masked_fill`, `normalize`, `cosine_similarity`

#### PyTorch Parity — Autograd
- **New differentiable ops**: `leaky_relu`, `elu`, `softplus`, `mish`, `selu`, `hardswish`, `hardsigmoid`, `prelu`, `clamp_min`, `clamp_max`, `log1p`, `expm1`, `log2`, `log10`, `atan2`, `maximum`, `minimum`, `masked_fill`, `normalize`, `cosine_similarity`, `prod`, `prod_dim`, `cumsum`, `logsumexp`, `unsqueeze_many`, `cat_many`, `stack`, `triu`, `tril`
- **NN autograd ops**: `conv1d`, `conv_transpose1d`, `conv3d`, `conv_transpose3d`, `avg_pool2d`, `avg_pool1d`, `max_pool1d`, `adaptive_max_pool2d`, `instance_norm`, `group_norm`, `pixel_shuffle`, `pixel_unshuffle`, `bilinear`, `embedding_bag`, `im2col`, `col2im`

#### PyTorch Parity — Modules
- **Convolutions**: `Conv1d` (with `Conv1dBuilder`), `Conv3d` (with `Conv3dBuilder`), `ConvTranspose1d`, `ConvTranspose3d`
- **Recurrent**: `GRU` (multi-layer sequence module), `LSTM` (multi-layer sequence module) — match `nn.GRU`/`nn.LSTM` interface with `forward_seq`, batch-first support
- **Normalization**: `GroupNorm`, `InstanceNorm`, `RMSNorm`
- **Pooling**: `AvgPool2d`, `MaxPool1d`, `AvgPool1d`, `AdaptiveMaxPool2d`, `PixelShuffle`, `PixelUnshuffle`, `Upsample`, `Unfold`, `Fold`
- **Attention**: `MultiheadAttention` — self-attention and cross-attention with optional masking
- **Bilinear**: `Bilinear` — bilinear transformation `y = x1^T A x2 + b`
- **Activations**: `LeakyReLU`, `ELU`, `Softplus`, `Mish`, `SELU`, `Hardswish`, `Hardsigmoid`, `PReLU` (learnable), `Softmax`, `LogSoftmax`, `Flatten`
- **Dropout**: `AlphaDropout` — maintains self-normalizing property for SELU networks
- **Embedding**: `EmbeddingBag` — bag-of-embeddings with sum/mean/max aggregation
- **Padding**: `ZeroPad2d`, `ReflectionPad2d` — symmetric and asymmetric padding modules

#### PyTorch Parity — Losses
- `bce_loss` (from probabilities), `nll_loss`, `ctc_loss`, `focal_loss` (class imbalance), `triplet_margin_loss`, `cosine_embedding_loss`, `hinge_embedding_loss`, `margin_ranking_loss`, `poisson_nll_loss`

#### PyTorch Parity — Optimizers
- `RMSprop` (with `RMSpropBuilder` for parameter groups)
- `Adagrad` (with `AdagradBuilder` for parameter groups)
- `RAdam` — Rectified Adam with variance-aware warmup
- `NAdam` — Nesterov-accelerated Adam

#### PyTorch Parity — LR Schedulers
- `ExponentialLR` — exponential decay (`lr = base_lr * gamma^step`)
- `MultiStepLR` — decay at specific milestones
- `OneCycleLR` — super-convergence schedule (warmup + cosine decay)
- `CyclicLR` — triangular wave between base and max LR (symmetric and asymmetric)

#### PyTorch Parity — Initialization
- `kaiming_uniform`, `kaiming_normal` now re-exported at crate root
- New: `uniform`, `normal`, `orthogonal`, `trunc_normal`, `uniform_bias`

#### Test Coverage (+165 tests, 769 total)
- **Autograd gradient verification** (55 tests): finite-difference checks for every new differentiable op — `leaky_relu`, `elu`, `softplus`, `mish`, `selu`, `hardswish`, `hardsigmoid`, `prelu`, `clamp_min`/`clamp_max`, `log1p`, `expm1`, `log2`, `log10`, `maximum`, `minimum`, `masked_fill`, `cosine_similarity`, `normalize`, `prod`, `cumsum`, `logsumexp`, `tril`, `flatten`; fused NN op gradients for all conv variants (1d/2d/3d + transpose), all pooling variants, `layer_norm`, `group_norm`, `instance_norm`, `bilinear`, `embedding_bag`, `pixel_shuffle`/`unshuffle`, `im2col`/`col2im`, `grid_sample`, `gru_cell`, `lstm_cell`; Variable API coverage (`set_grad`, `set_requires_grad`, `is_leaf`, `numel`, `zero_grad_set_to_none`, `set_data`, `to_device`)
- **Module forward/backward** (60+ tests): Conv1d (builder, groups, stride/padding, no-bias, gradient), Conv2d (builder, grouped, stride, no-bias, gradient), Conv3d, ConvTranspose1d/2d/3d (forward, gradient, stride, parameters), GroupNorm (batch-size-one, single-group, groups=channels, gradient), InstanceNorm (3D input, affine parameters, gradient), LayerNorm (3D, normalization, gradient), BatchNorm/BatchNorm2d (training, eval, running stats, rejects invalid dims, gradient), Bilinear (gradient, no-bias, rejects single input), Dropout (training, eval identity, p=0), ZeroPad2d/ReflectionPad2d (asymmetric, values, no-parameters)
- **Loss functions** (20+ tests): MSE (basic, zero loss), cross-entropy (class indices, wrong predictions, gradient), BCE/BCEWithLogits (gradient), L1, SmoothL1 (negative beta rejection), KLDiv, CTC, focal (reduces to CE at gamma=0), triplet margin (zero when far), cosine embedding (similar/dissimilar), hinge embedding (positive/negative), margin ranking (with margin), Poisson NLL (log/no-log)
- **Mixed precision** (7 tests): AutocastGuard lifecycle, autocast closure, GradScaler (defaults, scale, step finite/inf, update growth/backoff, state roundtrip), cast_parameters (basic, noop same dtype)
- **Gradient clipping** (6 tests): clip_grad_norm (scales down, no-op when small, multiple params), clip_grad_value (clamps, no-op, no-grad params)
- **Graph observation** (8 tests): collect/flush/trend pipeline, reduction modes (mean, sum, min, max, norm, scalar passthrough), rejects non-scalar, map operations (over tag, slices, batched, gradient, error cases)

## [0.2.0] - 2026-03-29

### Added

#### Graph Tree (hierarchical composition)
- **Label-path addressing**: Dot-separated paths (`"encoder.scan.hidden"`) for addressing subgraphs and tags across graph boundaries. Strict dot semantics -- dots always mean subgraph boundaries, no fuzzy resolution.
- **Tree registration**: Labeled graphs nested via `FlowBuilder` are automatically detected as child subgraphs. `tree_children()`, `child_graph()`, `subgraph()` for navigation. `is_composed()` flag on child graphs.
- **Selective freeze/thaw**: `freeze("encoder.read")`, `thaw("encoder.scan")`, `is_frozen("encoder")` -- declarative training phase control by label path.
- **Path-based parameter collection**: `parameters_at()`, `named_parameters_at()`, `named_buffers_at()` for per-subgraph optimizer groups. Target namespace used for checkpoint compatibility.
- **Subgraph checkpoint loading**: `load_subgraph_checkpoint("encoder", "encoder_v1.fdl.gz")` -- loads a checkpoint into a specific subgraph using the child's own namespace and structural hash validation.
- **Cross-boundary observation**: `tagged_at()` (null/nil semantics), `collect_at()`, `record_at()`, `trend_at()` -- read tagged outputs and metrics across graph boundaries.
- **Tree-aware flush and metrics**: `flush()` automatically recurses into labeled child subgraphs. `latest_metrics()` collects from the entire tree with dotted prefixes (`"encoder.loss"`). `Monitor::log()` sees the whole tree with zero extra code. `flush_local()` and `latest_metrics_local()` for independent per-subgraph observation cadences.
- **Internal tags**: Tags prefixed with `_` are auto-internal (hidden from parent resolution). Explicit `.internal("tag")` on FlowBuilder. Cross-boundary resolution rejects internal tags.
- **Training mode propagation**: `set_training_at("encoder", false)` for selective eval mode on subgraphs (BatchNorm running stats).
- **Verbose build output**: `.verbose(true)` on FlowBuilder prints tree structure, tag resolution, and parameter summary. `tree_summary()`, `param_summary()` methods.
- **Path validation**: `validate_path()` returns `PathKind::Subgraph` or `PathKind::Tag` for build-time wiring checks.
- **Module trait**: Added `as_graph()` method (default `None`, overridden in Graph) for subgraph detection.
- **Zero forward-path impact**: All tree metadata is build-time/query-time only. The pre-computed Vec routing in `forward_impl()` is untouched.

#### Modules
- **`GaussianBlur`**: Stateless `Module` wrapper around `gaussian_blur_2d()` for use in `FlowBuilder` graphs. Fixed sigma, no parameters. Kernel size auto-computed from sigma (`2 * ceil(3 * sigma) + 1`).

#### Checkpoint Migration
- **`migrate_checkpoint()`** / **`migrate_checkpoint_file()`**: Automatically remap parameter names from an older checkpoint to match a model's current naming. Matches by exact name first, then by shape+dtype in positional order. Handles params and buffers, supports `.gz` compression. Returns a `MigrateReport` with `unchanged`, `remapped`, `dropped`, `missing` fields and a `Display` impl for human-readable output.
- **`checkpoint_version()`**: Peek at a checkpoint file's version without loading it. Returns `1` for flodl 0.1.x, `2` for 0.2.0+.
- **`MigrateReport`**: Full accounting of a migration — `is_complete()` returns true when nothing was dropped or missing.

### Changed
- **Breaking**: Checkpoint format version bumped to v2. Checkpoints saved with 0.2.0+ write version 2; `load_checkpoint` accepts both v1 and v2 (binary layout is identical, only naming conventions differ). v1 checkpoints can be migrated with `migrate_checkpoint_file()`.
- **Breaking**: Restructuring a graph with `.label()` or renaming tags changes the parameter names that feed into `structural_hash()` — the hash algorithm is unchanged, but its inputs differ. Checkpoints saved before restructuring will fail architecture validation on load. Use `migrate_checkpoint_file()` to remap parameter names, or retrain.

## [0.1.5] - 2026-03-25

### Added
- `make docs-rs` — local docs.rs build validation via disposable Docker container (nightly Rust, `--cfg docsrs`, no libtorch). Catches docs.rs failures before publishing.

### Fixed
- Fix docs.rs build: `rand` 0.9.2 uses `feature(doc_auto_cfg)` removed in nightly 1.92+. Made `rand` an optional dependency (`rng` feature, on by default) so docs.rs can build without it.
- Fix flaky `test_clip_grad_norm` — seed RNG for deterministic weights.
- Fix rustdoc broken intra-doc links in `Tensor` (escaped shape brackets, qualified method paths).

## [0.1.4] - 2026-03-25

### Fixed
- Disable example scraping on docs.rs — examples require libtorch which the docs.rs sandbox doesn't have. The scraping failure corrupted dependency artifacts, breaking the doc build.

## [0.1.3] - 2026-03-25

### Added

#### GPU Performance
- **Fused Adam/AdamW**: `_fused_adamw_` single multi-tensor CUDA kernel for the complete optimizer step across all parameters. Reduces ~4N kernel launches to 1 per parameter group. Automatic on CUDA — no API change needed. `grad_scale`/`found_inf` params exposed for GradScaler integration.
- **Foreach operations**: 7 batched tensor ops that reduce CUDA kernel launches — `foreach_add_scalar_`, `foreach_mul_scalar_`, `foreach_zero_`, `foreach_add_list_`, `foreach_norm`, `foreach_lerp_scalar_`, `foreach_sqrt_`. Used internally by fused optimizers and gradient clipping.
- **Fused gradient clipping**: `clip_grad_norm` now uses `_foreach_norm` + `_foreach_mul_` internally (2 kernels instead of 2N).
- **CUDA Graphs**: `CudaGraph` struct with capture/replay/reset for zero CPU dispatch overhead. `cuda_graph_capture()` convenience helper with warmup. `MemPoolId`, `CaptureMode` (Global/ThreadLocal/Relaxed), `cuda_graph_pool_handle()` for memory pool sharing. 2-5x speedup for models with many small kernels.
- **Autocast (AMP)**: `AutocastGuard` RAII wrapper and `autocast()` closure helper for automatic mixed-precision dispatch. Eligible ops (matmul, conv, linear) run in Float16/BFloat16 on Tensor Core GPUs. Up to 3x speedup on RTX 30xx+.
- **GradScaler**: Dynamic loss scaling for mixed-precision training. Scale, unscale with inf/nan detection, step with skip-on-inf, update with growth/backoff.

#### Tensor Operations
- **Channels-last memory format**: `Tensor::to_channels_last()` and `is_channels_last()` for NHWC layout. 8-35% speedup for Conv2d on Tensor Core GPUs.
- **Non-blocking device transfer**: `Tensor::to_device_async()` for overlapped CPU-to-GPU transfer. Pair with `pin_memory()` for maximum overlap.
- **`Tensor::copy_()`**: In-place copy with `non_blocking` parameter for async CUDA transfers. Used by CUDA Graph capture for data loading.
- **`Tensor::pin_memory()`** and `is_pinned()`: Page-locked CPU memory for fast async GPU transfers.
- **Peak VRAM tracking**: `cuda_peak_active_bytes()`, `cuda_peak_reserved_bytes()`, `cuda_reset_peak_stats()` — matches `torch.cuda.max_memory_allocated()` / `max_memory_reserved()` / `reset_peak_memory_stats()` semantics. With `_idx` variants for multi-GPU.

#### Graph Engine
- **Pre-computed routing**: `Graph::build()` pre-computes a Vec-indexed routing table. Forward dispatch uses flat array indexing instead of HashMap lookups. Cached execution buffers reused across forward calls. Zero allocation during inference.
- **Vectorized gate combination**: Gate routing stacks all expert outputs and combines via broadcast multiply + sum (~3 kernel launches regardless of expert count, vs 3N with sequential accumulation).
- **Loop fast-path**: `for_n` loops detect at call time whether refs are needed and call `body.forward()` directly when no `.using()` is chained, skipping HashMap construction and `body_step` indirection.

#### Other
- **`MaxPool2d`** module: 2D max pooling with kernel size, stride, padding, dilation, and ceil mode.
- **`Rng`** struct: CPU-side RNG (SmallRng/Xoshiro256++) with seed, shuffle, bernoulli, range, normal.
- **`manual_seed(u64)`** / **`cuda_manual_seed_all(u64)`**: Seed libtorch RNGs for reproducibility.
- **`cuda_active_bytes()`**: Query bytes backing live tensors (matches `torch.cuda.memory_allocated()`).

### Fixed
- **VRAM monitoring**: `cuda_allocated_bytes()` now returns `reserved_bytes` from the allocator, making spill detection work.
- Removed unused `ResourceSample::vram_used_bytes` field.
- Dashboard uses `vram_alloc` as the sole VRAM metric.

### Changed
- **Benchmark suite**: Publication-grade methodology with interleaved multi-round execution (`--rounds N`), GPU clock locking (`--lock-clocks FREQ`), configurable warmup (`--warmup-secs`). 7 benchmarks (3 standard + 4 graph-builder). Peak VRAM tracking (not snapshots). WSL2 host-side clock management via `bench-publish.ps1`. `make bench-publish` for reproducible runs.
- **Docker**: `.dockerignore`, BuildKit cache for libtorch downloads, skip-if-exists image targets, dedicated bench image.

## [0.1.2] - 2026-03-19

### Added
- **VRAM spill detection**: New FFI function `flodl_cuda_alloc_bytes` queries libtorch's CUDA caching allocator. `cuda_allocated_bytes()` / `cuda_allocated_bytes_idx()` expose it in Rust. When allocated bytes exceed physical VRAM, the monitor shows spill in terminal output, live dashboard, CSV export, and epoch log.
- `ResourceSample::vram_allocated_bytes` field for allocator-level memory tracking.
- `vram_spill` column in CSV export.

### Fixed
- README links now use absolute GitHub URLs — fixes broken links on crates.io where relative paths don't resolve.

## [0.1.1] - 2026-03-18

### Fixed
- Replace `sha2` with `hmac-sha256` — fixes docs.rs build (sha2's asm feature doesn't compile on docs.rs).
- Widen leak test tolerance for CI parallel test jitter.

## [0.1.0] - 2026-03-18

### Added
- **Graph identity**: `Graph::structural_hash()` — deterministic SHA-256 hash of graph topology, module names, and parameter/buffer shapes. Any architecture change produces a different hash. `Graph::short_hash()` returns the first 8 chars. `FlowBuilder::label()` sets a human-readable name (does not affect hash).
- **Checkpoint architecture validation**: Checkpoint format v1 embeds a 32-byte structural hash. `load_checkpoint` / `load_checkpoint_file` accept an optional hash and error on architecture mismatch.
- **Dashboard metadata**: `Monitor::set_metadata(serde_json::Value)` attaches hyperparameters/config to the HTML archive. `watch()` / `watch_profiled()` capture graph label and hash. Dashboard header shows `"floDl — {label} [{hash8}]"`.
- **Parameter freezing**: `Parameter::freeze()`, `unfreeze()`, `is_frozen()` — disable/enable gradient tracking per parameter. Optimizers automatically skip frozen params (no grad). `Parameter::to_device()` now preserves frozen state.
- **Named checkpoints**: `Graph::named_parameters()` and `named_buffers()` return qualified names (`"tag/weight"` or `"node_id/running_mean"`). `save_checkpoint` / `load_checkpoint` persist both parameters and buffers (e.g., BatchNorm running stats), matching by name for partial loading. `LoadReport` reports what was loaded, skipped, and missing.
- **Optimizer parameter groups**: `Adam::with_groups()`, `SGD::with_groups()`, `AdamW::with_groups()` — builder API for per-group learning rates. `Optimizer::set_group_lr()` adjusts a single group; `set_lr()` updates all groups. Groups are persisted through `Stateful` save/load.

### Core Stack
- **Tensor**: Owned RAII tensors with Drop, ~72 operations. CPU and CUDA (feature-gated).
- **Autograd**: Reverse-mode AD backed by libtorch's native autograd engine. 37 differentiable operations with numerical gradient verification.
- **NN Modules**: Linear, Conv2d, ConvTranspose2d, LayerNorm, BatchNorm, Dropout, Embedding, GRUCell, LSTMCell.
- **Activations**: ReLU, Sigmoid, Tanh, GELU, SiLU.
- **Losses**: mse_loss, cross_entropy_loss, bce_with_logits_loss, l1_loss, smooth_l1_loss, kl_div_loss.
- **Optimizers**: SGD (with momentum), Adam, AdamW.

### Graph Builder
- Fluent API: from/through/build, split/merge, also (residual), tag/using (named refs).
- Loop constructs: for_n (fixed), while_cond (pre-condition), until_cond (post-condition).
- Routing: gate (soft, weighted), switch (hard, selected branch only).
- Map constructs: each, over, slices, with batched fast path.
- Input (auxiliary graph inputs), tag_group (auto-suffixed parallel branch names).

### Training Tools
- LR scheduling: StepDecay, CosineScheduler, WarmupScheduler (composable), PlateauScheduler.
- Mixed precision: Float16/BFloat16 dtype casting, GradScaler for loss scaling.
- Gradient clipping: clip_grad_norm, clip_grad_value.
- Checkpointing: save_checkpoint/load_checkpoint (named binary format with LoadReport, persists parameters + buffers, structural hash validation, file or io::Write).
- Weight initialization: kaiming_uniform/normal, xavier_uniform/normal.

### Training Monitor
- Human-readable ETA with adaptive formatting (hours/minutes/seconds/milliseconds).
- System resource tracking: CPU, RAM, GPU utilization (NVML), VRAM usage.
- Live web dashboard via embedded HTTP server with Server-Sent Events.
- Dashboard features: real-time training curves, resource usage charts, epoch log, graph SVG, label/hash header, metadata card.
- CSV and log file export.

### Observation & Visualization
- Tag-based metric collection: collect/flush/trend.
- Trend analysis: slope, stalled, improving, converged.
- Group trends with tag_group expansion.
- DOT/SVG graph visualization with parameter counts and node type shapes.
- Profiling: enable_profiling, profile, timing trends.
- Training curves: plot_html, export_trends, write_log.

### Infrastructure
- **CI**: GitHub Actions with CPU test matrix and CUDA build verification.
- **Docker**: CPU and CUDA Dockerfiles, docker-compose with GPU support.
- **Build**: Makefile with cpu/cuda targets (build, test, clippy, shell).

### Testing
- 389 library tests + showcase tests.
- Zero clippy warnings.
- Autograd numerical gradient checks.
- Module-level gradient checks.

### Key Design Decisions
- **Deterministic VRAM**: Rust's Drop trait replaces 5 phases of GC-based memory management.
- **No GC overhead**: No runtime.KeepAlive, no pending-free queues, no VRAM budget heuristics.
- **Variable**: `Rc<RefCell<VariableInner>>` for cheap Clone with interior mutability.
- **Module trait**: single-input forward + optional NamedInputModule for multi-input. `structural_hash()` for architecture identity.
- **Graph-as-Module**: Graph implements Module for hierarchical composition.
- **NamedInputModule on routers**: SoftmaxRouter and SigmoidRouter sum refs into input before projection.
- **Native FFI ops**: flodl_max, flodl_norm, flodl_cuda_mem_info, flodl_cuda_utilization.
