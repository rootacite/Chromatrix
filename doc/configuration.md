# Configuration (`config.toml`)

All training settings live in a single TOML file, **`config.toml` at the repo root**, read at startup by `trainer/config.py`. `trainer/main.py` accepts **no command-line arguments** — the TOML file (plus hardcoded fallbacks in `config.py`) is the only way to configure a run. Where both exist, **the TOML value always wins**.

You can edit this file by hand or with the Chromatrix dashboard's **Utils** tab, which validates values and preserves comments/formatting.

> ⚠️ The shipped `config.toml` contains the author's local paths (`/home/acite/...`, `/opt/models/...`). Replace them before running.

## Reading order

1. `config.toml` is parsed with `tomllib` and flattened into one dict (sections are just namespaces). The path is resolved **against the working directory**, so the trainer must be started from the repo root.
2. A `TrainConfig` dataclass is built from the flattened values; keys absent from the file fall back to hardcoded defaults in `trainer/config.py`.
3. Any key missing from both falls back to `None`.

## Sections and keys

### `[environment]` — paths

| Key | Example | Meaning |
| --- | --- | --- |
| `pretrained_model_name_or_path` | `"/opt/models/diffusers/waillu_170"` | SDXL base model. A diffusers directory, or a single-file checkpoint path (`from_single_file`). A single file carries no pipeline config of its own, so diffusers resolves the component configs from `stabilityai/stable-diffusion-xl-base-1.0`; that lookup is pinned cache-only (`load_sdxl_pipeline`), and diffusers downloads it once with a warning if the cache has never seen it. |
| `output_dir` | `"/home/acite/LLM/axltrainer/outputs"` | Root for run directories: each run writes `{output_dir}/{output_name}_{YYYYMMDD_HHMMSS}/…`. Created if missing. |
| `logging_dir` | `"/home/acite/LLM/axltrainer/logs"` | Root for TensorBoard logs: each run writes `{logging_dir}/{output_name}_{YYYYMMDD_HHMMSS}/`. Created if missing. |
| `train_data_dir` | `"/home/acite/LLM/Character/rein/"` | Dataset folder: images + same-named `.txt` captions. Optional `{stem}.mask.png` (white=train, black=ignore) enables masked loss; if missing, a transparent training image uses its alpha as the mask. Since `[[environment.train_data]]` exists, this key **mirrors that list's first entry** and is the single folder the paths that expect one read (checkpoint metadata, the Utils → Environment tag button, and a config that has no list). The trainer drops it as soon as the list has an entry. |
| `output_name` | `"rein"` | Run name; prefix of every artifact path, of the run directory, and of the TensorBoard project. It has to be one filename-safe token — letters and digits (any script), `-`, `_` and `.` — because the run id is `{output_name}_{YYYYMMDD_HHMMSS}` and the sample/checkpoint directories are named after it. A space, a slash or any other character the sanitizer would rewrite is refused by the Utils form, by `config_save`, and by the trainer at startup (`TrainConfig`), so a run can always be found again from its own id. |
| `amdfq` | `"none"` | Allocation patch for the next Train start: `"none"`, `"tail"` (`amdfq-tail-rs`), or `"vmm"` (`amdfq-vmm-rs`). Chromatrix Utils → **ROCm**. `start_train.sh` `LD_PRELOAD`s the matching release `.so`; a missing library fails the start instead of running unpatched. On RDNA 4, Tail or VMM is strongly preferred; VMM uses less VRAM system-wide because it bypasses ROCr's Memory Pool. |
| `amdfq_vram_reserve_gib` | `0.0` | GiB of driver-reported free VRAM (`/sys/class/drm/cardN/device/mem_info_vram_total − mem_info_vram_used`) the VMM hook will not consume. This is the amdgpu counter, not `hipMemGetInfo` (which does not see the compositor or RADV). The hooked `hipMemGetInfo` reports that remaining minus this floor so the caching allocator sees other clients. Before `hipMemCreate`, the hook compares the same counter against this floor plus the rounded request; if the allocation would leave less, `hipMalloc` returns OOM instead of creating or forwarding. **Optional**: this was the workaround for the driver handing a process's frames to another one on eviction, which the 2026-09 kernel fixed — leave it at `0` (`0` is also the default and means off) unless you run an older kernel. Chromatrix Utils → **ROCm**. Takes effect on the next Train start. Ignored unless `amdfq = "vmm"`. |
| `amdfq_va_never_reuse` | `false` | **Optional** VMM-hook switch, ignored unless `amdfq = "vmm"`. `false` (default): a `hipFree` gives its range's GPU virtual address back to the driver, so the address is reusable and the Dashboard's VA bar only shows what the hook holds right now. `true`: the pre-fix behaviour, kept for an older kernel — a range that was mapped once keeps its VA for the process lifetime and is never mapped again, so that bar only grows. The workaround existed because tearing a mapping down used to leave the compute VM's TLB stale, which made same-address reuse unsafe; the 2026-09 kernel fixed that. Chromatrix Utils → **ROCm**. Takes effect on the next Train start. |
| `amdfq_pool_mib` | `64` | **Optional** VMM-hook allocation pool, in MiB; ignored unless `amdfq = "vmm"`. `0` is off: every `hipMalloc` gets its own `hipMemCreate` + reserve + map. A value in `16`–`512` turns on one `hipMemCreate` per pool of that size: a request of **at most half the pool size** is carved out of a pool that already exists (no driver call at all), and anything larger keeps its own handle. Several pools may exist at once, a new one is built when no existing pool has room, and a pool is released — handle, mapping and (unless `amdfq_va_never_reuse`) its VA — once the upper layer has freed every block carved out of it. Values outside `16`–`512` are clamped by the hook, and a pool that cannot be built completely falls back to the per-request route. Chromatrix Utils → **ROCm**. Takes effect on the next Train start. The hook's own default, with `AMDFQ_POOL_SIZE` unset, is off; this row is what the shipped config asks for, and it is the value the pool-size sweep measured as 0.6 % *slower* than no pool at all on this repo's own workload (`test/bench_alloc_pool.py`).<br><br>**A pool is not better when bigger.** It is committed VRAM the driver cannot hand to anything else until its last block is freed, so an oversized pool risks OOM and fragmenting the card, and the savings fall off — the small-request traffic it removes is a bounded share of each step. One more consequence of sharing: blocks inside a pool are neighbours, so an over-read past a block still lands in mapped memory but an over-*write* past its end can reach another live block, where a solo allocation would have hit the throwaway pad behind it. |

### `[[environment.train_data]]` — dataset folders and their repeats

The datasets a run trains on: one block per folder, `repeat` = how often that folder's images are
drawn inside a single epoch.

```toml
train_data_dir = "/home/acite/LLM/Character/LLLJ/"   # mirrors the first block
output_name = "lllj"

[[environment.train_data]]
path = "/home/acite/LLM/Character/LLLJ/"
repeat = 3

[[environment.train_data]]
path = "/home/acite/Pictures/05_babara"
repeat = 1
```

| Key | Default | Meaning |
| --- | --- | --- |
| `path` | — (required) | Dataset folder, same shape as `train_data_dir` (images + same-named `.txt` captions, optional `{stem}.mask.png`). |
| `repeat` | `1` | How many times this folder is drawn inside one epoch, `1`–`512`. A missing path and a repeat outside the range are refused at startup with `train_data[<i>]: …`; `train_data` must be an array of tables. |

- **No block at all** means one entry built from the `train_data_dir` scalar with `repeat = 1`, which is
  what every config written before this list keeps doing.
- The repeat reaches training in one place: the folder's images get their record index **repeated** in the
  bucket list the batch sampler draws from. So one epoch is `images × repeat` samples, and `len(dataloader)`
  — from which `steps_per_epoch`, the total step count and the progress bars are all
  derived — grows with the sum. `len(dataset)` itself stays the number of unique images (the latent warm-up
  walks that index range, and must not reload one latent per repeat).
- A batch is still one aspect-ratio bucket's worth of images, so a repeated image can land in the same batch
  as its own copy (with its own noise draw and its own weight in the batch mean). A small folder with a large
  repeat can therefore fill a batch with near-copies of the same few images.
- Each folder keeps **its own** `<folder>/.latents_cache/`: the cache key hashes the absolute image path
  and the fit geometry, so two folders never collide and a folder's cache is re-encoded on its own.

Chromatrix's Utils → Environment section is the editor (a row per folder with its repeat), and the Images,
Statistics and Tag dataset surfaces act on the folder selected there. `[[validation.samples]]`'s own
`repeat` is unrelated: that one is how many images a sample point renders.

### `[model_spec]` — base-model family + checkpoint metadata

`base_model_version` is the **dispatch key**. The trainer looks it up in a catalog (`trainer/family.py`, mirrored in Chromatrix `ModelSpecCatalog`) and loads that family's pipeline / LoRA / loss path. The other three keys must match the catalog row for that version (hand-edits that drift are rejected at `TrainConfig` load). Chromatrix's Utils tab exposes a dropdown; changing it rewrites the three metadata strings.

| `base_model_version` | Trainable | `modelspec_architecture` | `modelspec_implementation` | `modelspec_sai_model_spec` |
| --- | --- | --- | --- | --- |
| `sdxl_base_v1-0` | yes | `stable-diffusion-xl-v1-base/lora` | `https://github.com/Stability-AI/generative-models` | `1.0.0` |
| `sd3.5-large` | **no** (UI slot only) | `stable-diffusion-v3-5-large/lora` | `https://github.com/Stability-AI/sd3.5` | `1.0.0` |

These also populate `modelspec.*` and `ss_base_model_version` on every `.safetensors`. `modelspec.prediction_type` and `ss_v_pred` record what the **base** declared (`v_prediction` for a v-pred base, otherwise `epsilon`), and sample rendering uses the same value. `ss_min_snr_gamma` records the gamma that actually ran (kohya's key, but the effective value: `0` for a v-pred base and for an epsilon one that asked for none), so a checkpoint says whether its loss was weighted. Selecting `sd3.5-large` is valid config; `train_start` / `build_train_objects` fail before loading weights.

### `[training]` — core training settings

| Key | Default (file) | Notes |
| --- | --- | --- |
| — | — | There is **no** prediction-type switch: it is read from the base. A single-file checkpoint carries two marker tensors (`v_pred`, `ztsnr`) that say what it was trained to predict — the same keys ComfyUI reads in `supported_models.py:229`; a diffusers directory answers with its own `scheduler/scheduler_config.json`. `TrainConfig.prediction_type` / `zero_terminal_snr` are derived from that on every construction (like `run_dir`, not a config key), the noise scheduler and the loss target follow it, and so does sample rendering (`trainer/models.py` `sample_scheduler_kwargs`). A base stripped of its markers cannot be detected — use the original file. |
| `min_snr_gamma` | `5.0` | Min-SNR weighting for an **epsilon** base: each sample's loss is scaled by `min(SNR, γ) / SNR`, with SNR read from the training scheduler's own `alphas_cumprod` (kohya's `apply_snr_weight`), so the low-noise steps are down-weighted — at γ=5 with SDXL's betas only 147 of the 1000 steps are scaled at all (mean weight 0.92; t=0 by 1/235), which is why the logged loss drops with it on. `0` (or a negative value) is **off**, not "γ = 0". A **v-prediction** base ignores it silently whatever the file says: `TrainConfig` derives `0` for it in the same place it derives the prediction type itself. The logged `Train/Loss` / `Train/Avg_Loss` are the weighted values, so their scale is not comparable with a run that had the weighting off. The Python fallback default is `0.0`; the shipped file asks for `5.0`. |
| `seed` | `1145141919` | Global training seed. |
| `mixed_precision` | `"bf16"` | `"bf16"` / `"fp16"` / `"no"`. |
| `train_batch_size` | `4` | Per-device batch size. |
| `gradient_accumulation_steps` | `1` | Effective batch = `train_batch_size × gradient_accumulation_steps`. |
| `learning_rate` | `1.0` | **Metadata only** (`ss_learning_rate`). Actual LRs come from `[unet_optimizer]` / `[te_optimizer]`. |
| `epoch` | `16` | Total epochs for this run. |
| `save_every_n_epochs` | `1` | **Defined but not used**; checkpoints are driven by `save_every_n_steps`. |
| `save_every_n_steps` | `100` | Steps between LoRA checkpoints (`0` writes none). The value here is what a run **starts** with; the Dashboard's Training Control card can retune it for the run in progress (a change restarts the countdown from the step that adopts it), and a run keeps its own cadence — the file is never rewritten by a live change. |
| `sampling_enabled` | `true` | Whether a checkpoint save also renders the `[[validation.samples]]` images. `false` keeps the same cadence but writes checkpoints only (the expensive part of a save point is the sampling, not the checkpoint). Changeable mid-run like the cadence; a checkpoint with no samples can be rendered later, one pass per checkpoint, from the Dashboard. |
| `val_split_percent` | `10.0` | Share of the dataset's **unique images** kept out of training for the validation loss (`0`–`90`). **`0` is the off switch**: nothing is held out, neither pass runs, no validation scalar is written, the run log says `Validation: off (val_split_percent = 0; …)`, and Utils greys `Val samples` / `Val interval` because their numbers are inert — their ranges are only enforced while the split is on (`TrainConfig.__post_init__` and the Kotlin form both exempt them, so a stale `0` in those fields cannot stop a run with the feature off). The count is `ceil(percent/100 × images)`, never every image, drawn once from the run's `seed` and the folder contents, and each held-out image also removes its folder's `repeat` draws per epoch — so the epoch length, the step count and `total_steps` shrink by that much. The split is *not* stored: it is reproducible from `seed`, `val_split_percent` and the folder contents, and the run prints `Validation split: N/M images held out`. |
| `val_sample_count` | `8` | Images scored per validation pass (`1`–`64`, checked only while `val_split_percent > 0`); a smaller held-out set uses all of it. **Two passes run per cadence step**, so this count is paid twice. Pass 1 draws a fresh random subset, seeded by the run's seed and the step, so successive points cover the held-out set; pass 2 scores a fixed, *mutually dissimilar* sample, picked once from the held-out images by 32×32-thumbnail similarity (`tools/cmp_img.py`'s metric, `trainer/validation_split.py::select_diverse_subset`) so no two scored images look alike and every pass sees the same ones. **One forward never carries more images than `train_batch_size`**: images are collated per aspect-ratio bucket and each group is chunked at the training batch size, so a pass cannot peak above the step it rides on, and this count is free to be larger than the batch — the aggregate stays the mean over the scored images. Cost scales with the count: measured on the author GPU a pass over 1 / 5 / 8 images costs ~0.24 / ~0.81 / ~1.53 s, i.e. ~3.1 s per cadence step at 8 — those figures predate the per-forward cap and describe one forward per bucket group. The cap trades a little time for the memory bound: the same 8-image pass measured 1.61 s at `train_batch_size = 1` (eight forwards of one image) against 1.28 s uncapped, and at the shipped batch of 3 it is three forwards of ≤3, so the penalty is far smaller. The marginal cost is ~140 ms per image while the images share a bucket and higher once they spread across aspect-ratio buckets, because each bucket group is its own forward. |
| `val_interval` | `5` | Steps between validation **steps**: the first is step 1, then one every `val_interval` (`1`, `1+N`, `1+2N`, …), so a short run still gets a point at the start it is compared against. `0` = never run one while the split stays on (checked only while `val_split_percent > 0`); to turn the whole feature off, set `val_split_percent = 0`. Each cadence step runs the two passes above and writes three scalars in one TensorBoard event, so they share one x axis: `Val/Loss` (the random subset's raw mean), `Val/Avg_Loss` (that series averaged over the current epoch's validation points — the same `LossRecorder` window rule as `Train/Avg_Loss`) and `Val/Fixed_Loss` (the fixed sample's raw mean, the curve that is comparable point to point). Measured on the author GPU (RX 9070 XT, batch 3, locon dim 48, ~10 % of an 80-image copy held out, runs under the `[environment].amdfq` patch, means over whole epochs, **one pass**): 8 images at interval 5 → +16.0 % per step (5 passes in a 25-step arm), 5 images at interval 1 → +45.9 %, 5 images at interval 10 → +4.1 % measured with the older every-Nth-step anchor (≈+5.4 % under the step-1 anchor; arithmetic, not a measurement). This feature's two passes double the validation cost, and a later probe run at batch 1 measured the pair directly: 786 → 1255 ms/step at interval 5 with 8 images (the pass itself 1.28 s) — the ratio depends on the step cost, so read the per-pass figure, not that percentage. The median instead of the mean shows only the typical step (+0.9 % at interval 5) because a coarse cadence has few slow steps. A re-measurement of the default pair could not complete at batch 3: the probe's **baseline** arm (no pass at all) needs ~16.2 GiB at its peak on a 16 GB card — driver counter, polled from outside the run: 16172 MiB of 16298 MiB, with 8.16 GiB already held once the pipeline is built — on a card whose driver baseline alone holds ~0.7 GiB that no process's DRM fd accounts for (the RPC helper `api.py` holds 0 MiB and does not import torch), i.e. ~130 MiB of headroom. The pass is not the cause (that arm runs none), but at this margin a pass can tip an already-tight run, so on a 16 GB card at batch 3 / 1024 resolution treat `val_interval` and `val_sample_count` as memory knobs as well as time knobs. The per-pass numbers above are from completed runs of the same arms; re-run the probe on a freshly idle card before repeating them. The isolation check — both passes leave the training step's loss and weights bit-identical — and the full method are in `doc/agent/tests.md` (`test/probe_val_loss_gpu.py`). The Dashboard draws `Val/Avg_Loss` and `Val/Fixed_Loss` beside `Train/Avg_Loss` in the **Train / Avg Loss** chart. |
| `resume_lora_path` | `""` | Optional. kohya LoRA `.safetensors` (or a checkpoint directory holding exactly one) loaded into the UNet + both text encoders **before** training. Weights only: step/epoch counting still starts at 0 and the run gets its own timestamped directory, so earlier runs are never overwritten. `network_type` and `network_dim` / `network_alpha` must match the checkpoint. See [Training → Resuming from a checkpoint](training.md#resuming-from-a-checkpoint). |

`run_dir` is **not** a config key you should write: the trainer fills it in at runtime with the absolute run directory created for that run.

### `[network]` — LoRA network

| Key | Default | Notes |
| --- | --- | --- |
| `network_type` | `"standard"` | `"standard"` (attention LoRA) or `"locon"` (Kohya LoRA-C3Lier on the UNet). See [LoCon](locon.md). |
| `network_dim` | `48` | LoRA rank `r`. |
| `network_alpha` | `24` | LoRA alpha. Scale ≈ `alpha / dim` (0.5 here). |
| `network_dropout` | `0.25` | LoRA dropout (`0.0`–`1.0`), regularization / overfitting control. |
| `conv_dim` | `0` | Locon only: rank of Conv2d 3×3 (and ResNet 1×1 shortcuts). May differ from `network_dim`. `0` with `network_type = "locon"` is invalid. |
| `conv_alpha` | `0` | Locon only: conv alpha. Scale is `conv_alpha / conv_dim`. May differ from `network_alpha`. |
| `clip_skip` | `1` | Hidden-state index used from the text encoders. |
| `max_token_length` | `225` | Upper bound on prompt tokens. Captions longer than CLIP's 75 content tokens are split into `model_max_length − 2` chunks; a batch is padded only to the longest caption in that batch (not always to this cap). Sampling still uses as many chunks as the sample prompt needs, up to this value. |

Standard wraps UNet `to_q` / `to_k` / `to_v` / `to_out.0` and TE `q_proj` / `k_proj` / `v_proj` / `out_proj`. Locon adds UNet Linear extras (`proj_in` / `proj_out` / `ff.net.0.proj` / `ff.net.2` / `time_emb_proj`) at `network_dim`, Conv2d extras (`conv1` / `conv2` / `conv_shortcut` / `conv`) at `conv_dim`, and TE MLP `fc1` / `fc2`. `conv_in` and `conv_out` stay unwrapped. Checkpoints write `ss_network_type` (`standard` or `locon`) and, for locon, `ss_network_args = "conv_dim=N conv_alpha=M"`.

### `[bucketing]` — aspect-ratio buckets

Each bucket holds about `train_resolution²` pixels and takes its aspect ratio from the image, so a
tall portrait gets a tall bucket instead of being squeezed into a short one and cropped. Whatever
mismatch is left between bucket and image is **letterboxed**: the whole image is fitted into the
bucket and the leftover bars carry loss weight 0, so they neither train nor count as content.

| Key | Default | Notes |
| --- | --- | --- |
| `enable_bucket` | `true` | Group images by aspect ratio instead of forcing one resolution. With it off, every image goes to a single `train_resolution × train_resolution` bucket. |
| `bucket_no_upscale` | `true` | A bucket side is never built larger than the image's own side, so fitting never upscales the image (the one exception: sources thinner than one `bucket_reso_steps`, which are floored at one step). |
| `train_resolution` | `1024` | Area anchor: each bucket aims at `train_resolution²` pixels (~1.05 MP at 1024) at whatever orientation the image has. |
| `bucket_reso_steps` | `128` | Bucket size granularity. **Keep at 128 on AMD ROCm** (see [Troubleshooting](troubleshooting.md#rocm-bucket-step-crash) — must be divisible by 16 to keep latent dims aligned). |
| `min_bucket_reso` | `384` | Smallest bucket side. This is the knob for extreme aspect ratios: lower it to give very tall art more resolution, rather than lowering `train_resolution`. |
| `max_bucket_reso` | `2688` | Largest bucket side. Keep `min_bucket_reso ≤ train_resolution ≤ max_bucket_reso`; otherwise every bucket lands on a clamp, loses the image's aspect ratio, and the trainer warns on stderr. |

### `[optimization]` — data & training optimizations

| Key | Default | Notes |
| --- | --- | --- |
| `cache_latents` | `true` | Pre-encode all images to latents before training. |
| `cache_latents_to_disk` | `true` | Persist encoded latents to `<train_data_dir>/.latents_cache/` (SHA1-keyed `.pt` files, atomic writes). Reused across runs while the file holds the keyed bucket's latent; a file that does not is re-encoded. |
| `gradient_checkpointing_unet` | `true` | After PEFT wrap, call `enable_gradient_checkpointing()` on the UNet. Saves VRAM by recomputing activations in backward; turn off for faster steps if the GPU has headroom. |
| `gradient_checkpointing_te` | `true` | Same for both text encoders (`gradient_checkpointing_enable` / `enable_gradient_checkpointing`, plus `enable_input_require_grads` because embeddings stay frozen). |
| `shuffle_caption` | `true` | Shuffle caption tokens after `keep_tokens`, deterministically per epoch. |
| `keep_tokens` | `2` | Number of leading caption tokens kept in place when shuffling. |
| `caption_extension` | `".txt"` | Caption file extension. |
| `noise_offset` | `0.05` | Adds a small offset to the noise target (aids contrast/color variety). |
| `flush_memory_every_step` | `true` | After each training batch, `gc.collect` + HIP/CUDA `empty_cache`. Disable if step time is dominated by allocator churn. |

### `[unet_optimizer]` — UNet optimizer (Schedule-Free AdamW)

| Key | Default | Notes |
| --- | --- | --- |
| `unet_learning_rate` | `5e-5` | **The actual UNet learning rate.** |
| `unet_weight_decay` | `0.01` | |
| `unet_betas_1` | `0.9` | |
| `unet_betas_2` | `0.99` | |
| `unet_warmup_steps` | `100` | Schedule-Free warmup (no separate LR scheduler is needed for the UNet). |
| `unet_max_grad_norm` | `1.0` | UNet gradient clipping (recorded as `ss_max_grad_norm`). Moved here from `[training].max_grad_norm`, which the loader still reads when this key is absent. |

Neither optimizer takes an `eps`: both keep the library's `1e-8`. Gradients are clipped separately
for the two parameter sets, just before each optimizer step — the UNet's LoRA parameters to
`unet_max_grad_norm` and the text encoders' to `te_max_grad_norm`. Nothing is clipped while gradient
accumulation is still summing: clipping runs only on the step that actually syncs gradients.

### `[te_optimizer]` — text-encoder optimizer (Schedule-Free AdamW)

| Key | Default | Notes |
| --- | --- | --- |
| `te_learning_rate` | `5e-6` | **The actual text-encoder learning rate** (usually 10× lower than UNet). |
| `te_weight_decay` | `0.01` | |
| `te_betas_1` | `0.9` | |
| `te_betas_2` | `0.99` | |
| `te_max_grad_norm` | `1.0` | Gradient clipping for the text encoders (the UNet's is `unet_max_grad_norm` above). |
| `te_warmup_steps` | `100` | Schedule-Free warmup of the text encoders (`unet_warmup_steps` is the UNet's own). This key used to be `[training].lr_warmup_steps`; the trainer and Chromatrix still read that one when `te_warmup_steps` is absent, so a config written before the move keeps its warmup. |

No LR scheduler is built for the text encoders.

### `[infrastructure]` — data loading

| Key | Default | Notes |
| --- | --- | --- |
| `max_data_loader_n_workers` | `20` | DataLoader worker count. |
| `persistent_workers` | `true` | Keep workers alive between epochs. |

### `[validation]` — sample generation

| Key | Default | Notes |
| --- | --- | --- |
| `sample_prompts` | `"(rein_character:1.1), ..."` | Positive prompt used for validation samples. Also the fallback prompt of a `[[validation.samples]]` entry that omits `prompt`. |
| `sample_negative` | `"worst quality, low quality, ..."` | Negative prompt (fallback for `negative`). |
| `sample_width` / `sample_height` | `1280` / `720` | Sample image size (fallbacks for `width` / `height`). |
| `sample_steps` | `55` | Denoising steps (fallback for `steps`). |
| `sample_seed` | `0` | `0` = unique random seed per image (printed to the log); otherwise `seed + repeat_idx` (fallback for `seed`). |
| `sample_repeat` | `3` | Number of samples per checkpoint (fallback for `repeat`). |
| `guidance_scale` | `6.0` | CFG scale (fallback for `guidance_scale`). |
| `guidance_rescale` | `0.0` | CFG-rescale strength (fallback for `guidance_rescale`): `0.0` leaves the CFG output alone, `1.0` replaces it with the standard-deviation-matched one. This is ComfyUI's `RescaleCFG` node and diffusers' `guidance_rescale` (both from [2305.08891](https://huggingface.co/papers/2305.08891)); the shipped config asks for `0.6`. It lifts the crushed shadows and burnt highlights a v-pred/zero-SNR base produces at a low CFG — same prompt and seed, `0.6` took the black-pixel share of a sample from 15.3 % to 7.7 % — and cannot rescue a prompt the model itself collapses on. |

#### `[[validation.samples]]` — one block per prompt set

Any number of these blocks turns validation into a multi-prompt pass. Every set renders its own
`repeat` images at each sampling point, in block order.

```toml
[[validation.samples]]
name = "classroom"        # optional tab label; blank = the prompt's first tag
prompt = "1girl, classroom, ..."
negative = "worst quality, ..."
width = 1152
height = 768
steps = 35
guidance_scale = 6.0
guidance_rescale = 0.6
seed = 1
repeat = 3
```

| Key | Required | Falls back to |
| --- | --- | --- |
| `prompt` | yes | `sample_prompts` |
| `negative`, `width`, `height`, `steps`, `guidance_scale`, `guidance_rescale`, `seed`, `repeat` | no | the `[validation]` scalar of the same shape |
| `name` | no | the prompt's first tag, else `Set N` |

- **No blocks at all** = exactly one set built from the scalars above, i.e. the single-prompt
  behaviour. `validation.sample_*` overrides (used by `test/verify_mask_pipeline.py`) keep working
  in that case.
- **Ranges** (enforced by `trainer/config.py` and by the Utils form): `width`/`height` 64–4096,
  `steps` 1–150, `guidance_scale` 0–30, `guidance_rescale` 0–1, `seed` 0–2³²−1, `repeat` 1–32,
  `prompt` non-empty.
  A violation aborts the run at startup with the offending index (`validation.samples[2]: steps …`).
- **Seed**: inside a set the nth image uses `seed + n` (`0` = a fresh random seed per image). Two
  sets that share a seed therefore start from the same noise, so only the prompt differs.
- **File names**: `{output_name}_{step:06d}_p{set}_{repeat}.png`, with `set` counting from 0. The
  two-number form of older runs (`…_{step}_{repeat}.png`) is still parsed, as set 0.
- Sampling time scales with `Σ repeat`; each set's images are rendered sequentially.
- **Editing the sets for one run**: the Dashboard's Dashboard → Sampling Prompts section saves a run's
  sets to `{logging_dir}/{run_id}/sample_sets.json`, which overrides `samples` wherever that run's
  prompts are resolved — its own sample points (a live run reads the file before every pass, so the
  next checkpoint uses it), a card's manual sample pass, and an evaluation. Absent, nothing changes:
  the file is written only by that section, never by a run, and this `config.toml` and the run's own
  copy of it are never rewritten. It is not a config key, so the Utils editor does not show it.
- The run's configuration is recorded in TensorBoard's **HParams** tab. `add_hparams` only
  accepts int/float/str/bool/tensor values, so a list-valued key such as `samples` is written
  as a JSON string (`tracker_hparams()` in `trainer/config.py`) rather than passed through raw.
- **A run also keeps its own copy of this file.** `trainer/main.py` copies the repo's `config.toml`
  verbatim to `{logging_dir}/{run_id}/config.toml` as soon as the run directory exists, because a
  run's sample images are *its* config's and the next run is free to edit the repo file. The
  Dashboard's per-checkpoint **Evaluate** action is what reads it back: it renders the missing
  samples and scores the tagger's labels against the prompt each image was rendered from, using
  this run's prompts rather than today's. A run from before these snapshots existed (or one whose
  snapshot is gone) falls back to the repo's current `config.toml`, and the evaluation record says
  which file it used (`config_source`).

### `[bookkeeping]`

Intentionally empty. The Python side treats missing keys as `None`; it exists for `ss_*` metadata fields that aren't always present (e.g. `ss_session_id`, `ss_training_comment`, model hashes, dataset dirs, bucket info).

## Derived values worth knowing

- **Effective batch size** = `train_batch_size × gradient_accumulation_steps`.
- **LoRA scale** = `network_alpha / network_dim` (0.5 with the defaults).
- **Steps per epoch** = `⌈len(dataloader) / gradient_accumulation_steps⌉`; **total steps** = steps-per-epoch × `epoch`.
- **UNet LR vs TE LR**: both use Schedule-Free AdamW — the UNet with its own warmup via `unet_warmup_steps`, the text encoders with `te_warmup_steps`. Each publishes its own scheduled LR, and the dashboard's `Learning Rate` chart draws the two against a left and a right axis.
- **Bucket and pad**: `pick_bucket_size` derives the bucket from the image's aspect ratio and the `train_resolution²` budget; `fit_geometry` then places the image inside it as `{fit_w}×{fit_h}` centred at an offset, and the rest of the bucket is pad. The trainer prints the bucket list and the mean pad for a run (`Letterbox: n/m samples padded, mean x%`).

## Editing from the GUI

The Chromatrix **Utils** tab is a validated form over exactly these sections/keys:

- Path fields have a Browse button (OS file dialog: the desktop portal picker on Linux).
- `mixed_precision` and `network_type` are segmented buttons / chips.
- Booleans are switches.
- Inline hints show derived values (effective batch, LoRA scale, bucket-step divisibility, sample aspect ratio).
- The **Validation** section edits `[[validation.samples]]` as horizontal tabs: one chip per set
  (its label, a warning icon when the set has an invalid field), `+` clones the open set, and the
  `×` on a chip deletes that set after a confirmation. The last set cannot be deleted. Saving writes
  the `[validation]` scalars from the first set plus one fully explicit block per tab (a blank label
  is left out), so the file never carries two contradictory prompts.
- The **Training** section carries the **Sampling** switch (`[training].sampling_enabled`) beside
  `save_every_n_steps`. Those two are the *starting* values: the Dashboard's Training Control card
  can change both for the run in progress without touching this file.
- Save runs full-form validation; on error it jumps to the first section with an invalid field (and to the offending set's tab). The writer is a line-preserving TOML patcher, so comments and formatting survive edits — except inside the replaced `[[validation.samples]]` blocks.
