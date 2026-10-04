# Training

This guide covers running training, what happens during a run, and how the pause / resume / early-stop machinery works.

## Running training

The trainer is launched with `start_train.sh`, which sets the AMD/ROCm environment (MIOpen cache dirs, log suppression, allocator settings) and runs:

```bash
bash start_train.sh
```

Equivalent to `python -u trainer/main.py` with stdout filtered of noisy driver lines. The working directory must be the repo root so `config.toml` resolves.

The dashboard starts it the same way — `api.py`'s `train_start` spawns `bash start_train.sh` detached (`setsid`), so **closing the GUI does not stop training**. `[environment].amdfq` (`none` / `tail` / `vmm`) is applied here as `LD_PRELOAD` (Chromatrix Utils → ROCm). A missing patch `.so` fails the start.

## What a run does, phase by phase

1. **Startup (`starting`)** — loads `config.toml`, creates this run's timestamped output + log directory, acquires the run lock (`train.lock`, fails fast if another run holds it), seeds RNG, resolves `[model_spec].base_model_version` to a model family, and builds that family's pipeline (LoRA adapters via PEFT, dataset + DataLoader, optimizers). When `[training].resume_lora_path` is set, the LoRA weights are loaded here (before `accelerator.prepare`). Unknown or inconsistent spec strings fail here; `sd3.5-large` is a catalogued family but training is not implemented yet.
2. **Encoding (`encoding`)** — if `cache_latents` and `cache_latents_to_disk` are on, all images are pre-encoded to latents by a 3-stage pipeline (CPU decode/resize/fit+pad → batched VAE encode per bucket → atomic `.pt` writes into that folder's `<folder>/.latents_cache/`). Already-cached images are skipped — a file that cannot be read, or that does not hold the keyed bucket's latent, is not one of them: it is re-encoded over the file and reported on stderr. The `.pt` name hashes the absolute path, the bucket **and** the fit geometry, so changing the bucket rule or the `[bucketing]` clamps re-encodes the dataset once instead of silently serving latents built from differently placed pixels, and two dataset folders never share a cache. Only the VAE is on the GPU (UNet + text encoders stay on CPU); encode batches are small and the VAE uses tiling. The VAE is moved back to CPU afterwards and GPU memory is flushed. Progress is published as `encoding.current/total`.
3. **Training (`training`)** — the epoch loop. The DataLoader's batch sampler draws each batch from a **single aspect-ratio bucket** so `train_batch_size` images share a resolution and stack in one UNet step (remainders smaller than the batch size are kept). Prompts are encoded in one batched CLIP-L + CLIP-G forward (chunked only as far as the longest caption in that batch, up to `max_token_length`; `clip_skip` applied), noise + timesteps are added, and the UNet predicts the noise target (with optional `noise_offset`). After gradient accumulation, UNet grads are clipped to `unet_max_grad_norm`, TE grads to `te_max_grad_norm`, and both optimizers step. Every `save_every_n_steps` steps the run saves a checkpoint, and — unless `sampling_enabled` is off — renders the validation samples for it. Both the cadence and the switch can be changed while the run is going (Dashboard → Training Control); the trainer takes the request at its next optimizer step and republishes what it is actually using.

   **Bucketing and padding.** Each image's bucket comes from its aspect ratio and the `train_resolution²` area budget, and the image is then **fitted whole into the bucket** (contain, centred) rather than centre-cropped: leftover bars are pad, and their loss weight is exactly 0. So no sample loses its head or feet, at the cost of a few percent of the bucket being unsupervised (`Letterbox: n/m samples padded, mean x%` is printed at startup). The pad is a neutral 127 grey. See [Configuration](configuration.md#bucketing--aspect-ratio-buckets).

   **Masked loss (optional).** Per-pixel MSE is multiplied by a 0–1 mask after area-downsampling to latent size (1/8). Content source, in order: `{stem}.mask.png` if present (white=train, black=ignore, gray=partial); else the training image's **alpha channel** (transparent=ignore); else all ones. Every sample carries the letterbox pad at weight 0, so the mask is always a full-bucket tensor, but only content masks are counted in the `Loss masks: n/m samples` line. This is *not* inpainting-model training: the UNet still sees the full noisy latent (pad included); only the loss is spatially weighted. Fine details smaller than one latent cell (hair, earrings) need a slightly larger painted region. Masks are not stored in `.latents_cache`. A sidecar always wins over embedded alpha. Because the mask is an unnormalized weight, a reported loss is scaled by the mean mask weight: a spatial mask of coverage *c* reports roughly *c* × the full-frame unmasked loss and produces a correspondingly smaller step (even with no sidecar and no alpha, the letterbox pad already lowers that mean below 1). `python test/verify_mask_pipeline.py --tiers all` (run it in the env from `environment.yml`, currently `axl`) re-runs the whole chain on your own machine — mask plumbing and fit geometry, the exact loss identities, and masked-vs-unmasked `trainer/main.py` runs with per-region probes — and writes a report under its `--report-dir`.
4. **Sampling (`sampling`)** — validation images are generated with the current LoRA weights (sampler Euler a: `EulerAncestralDiscreteScheduler` with `timestep_spacing="linspace"`, i.e. ComfyUI's `euler_ancestral` + `normal`; the prediction type follows the **base checkpoint**, whose `v_pred` / `ztsnr` marker tensors are read automatically (`v_prediction` + zero-terminal-SNR betas, else epsilons) — there is no switch, and training targets come from the same two fields; interruptible denoising). After prompt encode the text encoders are offloaded; after each denoise pass the UNet is offloaded before VAE decode (slicing + tiling). Returning to the training loop restores UNet + both TEs to the train device. Each `[[validation.samples]]` entry is rendered in turn (its own size, steps, CFG and seed), and one checkpoint's samples are saved as `<output_name>_<step:06d>_p<set>_<repeat>.png` in `{output_dir}/{run_id}/{output_name}_samples/`. The prompts a run samples with are its own: the `config.toml` copy `main.py` keeps beside its logs (`{logging_dir}/{run_id}/config.toml`), or the sets saved for that one run from the Dashboard's Sampling Prompts section (`{logging_dir}/{run_id}/sample_sets.json`, which layers over that copy). The trainer reads the file before every sample point, so a change made while the run is live applies at its next checkpoint; the same resolution is what a card's manual sample pass and an evaluation use. Sampling has no cadence of its own: it happens exactly when a checkpoint is written, which is why a sample can always be traced back to a checkpoint. Turning `sampling_enabled` off (before or during a run) makes a save point checkpoint-only; a checkpoint that has no samples — because sampling was off, or because it is an early one you skipped — can be rendered afterwards, one pass per checkpoint, from the Dashboard's Checkpoints section. That pass runs detached while the GPU is free (the run is paused, stopped or over) and writes its images to `{output_name}_samples/generated/`, so the run's own sample files are never overwritten. A **step range** can be rendered in one go (`Sample range` in the Dashboard's Checkpoints section): every checkpoint of the run whose step is inside the range is done oldest first by a single process, which pays the model load once and hands each checkpoint its own job, so the cards fill in as it goes. `Stop` asks it to finish the step it is in and stop; what was already rendered stays.
5. **Finish (`finished`)** — the final LoRA is saved (unless stopped early), and the lock is released. On exception the status becomes `error` and the traceback is recorded.

TensorBoard metrics are written to `{logging_dir}/{run_id}/`:

| Tag | Meaning |
| --- | --- |
| `Train/Loss` | Per-step MSE loss; the Min-SNR-weighted value when `[training].min_snr_gamma` is active (epsilon bases only), so its scale is not comparable with a run that had the weighting off. |
| `Train/Avg_Loss` | Kohya-style epoch-window moving average of the same value. |
| `UNet/LR/Effective_Actual_LR` | Schedule-Free UNet effective LR. |
| `TE/LR/Effective_Actual_LR` | Schedule-Free text-encoder effective LR. |

## Pause / resume / early stop

Control is file-based: an external caller (the dashboard or `api.py`) writes a one-shot command to `command.json` (`pause` / `resume` / `stop`), and the trainer consumes it at the next **swap-safe point** — after each encoding item, after each optimizer step, and after each denoising step during sampling.

### Pause (GPU offload)

`pause` offloads everything to CPU in stages — UNet → text encoders → optimizer state (including Schedule-Free's `z` / `exp_avg_sq`) → VAE — then calls `empty_cache`. Progress is published as `swap.{stage, detail, current, total}` while the status is `pausing`; when done the status becomes `paused` with `paused_from` recording which phase (encoding / training / sampling) was interrupted.

While paused, the trainer process sleeps at the safe point and **keeps running** (no GPU memory in use). GPU memory is released so you can use the card for something else.

### Resume

`resume` reloads what the paused phase needs (only the VAE for `encoding`; UNet + text encoders + optimizers for `training`/`sampling`), restores train/eval modes, and returns to the phase it left. Status transitions `resuming` → `encoding` / `training` / `sampling`.

### Early stop

`stop` sets status `stopping`; the current phase aborts at the next safe point. The behavior depends on where the stop lands:

- **During encoding** — no LoRA is saved (`stopped_during = encoding`).
- **During training** — if `global_step > 0` and that step has no checkpoint yet, an emergency final checkpoint is saved as `{output_dir}/{output_name}_final/{output_name}.safetensors` (`stopped_during = training`).
- **During sampling** — leftover repeats are skipped; the step's checkpoint already exists.

In all cases the run ends in `finished` (with a `detail` of `stopped_during_*`), not `error`.

## Checkpoint and artifact layout

Every run creates its own directory, named `{output_name}_{YYYYMMDD_HHMMSS}` (a `_2` / `_3` suffix is appended if that name is taken). Inside it the artifact names are unchanged:

```
run_id = {output_name}_{YYYYMMDD_HHMMSS}
```

| Artifact | Path |
| --- | --- |
| Per-step LoRA | `{output_dir}/{run_id}/{name}_s{step:06d}/{name}.safetensors` |
| Per-epoch LoRA (unused today) | `{output_dir}/{run_id}/{name}_e{epoch:03d}_s{step:06d}/{name}.safetensors` |
| Final LoRA | `{output_dir}/{run_id}/{name}_final/{name}.safetensors` |
| Sample images | `{output_dir}/{run_id}/{name}_samples/{name}_{step:06d}_p{set}_{repeat}.png` |
| TensorBoard logs | `{logging_dir}/{run_id}/` |
| This run's prompt sets (only once edited in the Dashboard) | `{logging_dir}/{run_id}/sample_sets.json` |
| Latent cache | one per dataset folder: `<folder>/.latents_cache/<sha1(abs_path::bucket::fit geometry)>.pt` |
| Runtime state / commands / lock / log | `$AXL_RUNTIME_DIR` → `$XDG_RUNTIME_DIR/axltrainer` → `/tmp/axltrainer-$UID` (`state.json`, `command.json`, `train.lock`, `train.log`) |

`state.json` carries the current `run_id`, and the dashboard / `list_samples` / `train_reset` resolve a run as: explicit `run_id` argument → `state.json`'s `run_id` → the newest run directory of an explicitly named `output_name`. A request that names nothing means "the run the trainer is on", so it stops at `state.json`: with no run recorded the dashboard follows none and says `Nothing started yet`, and a run the trainer never recorded — or one whose directories are gone — is picked from the run history, which lists every run directory of both roots. `run_id` alone is enough: when `name` is not passed, the name the run id was built from is used. Runs created before this layout (flat `{output_dir}/{name}_s000010/`, `{logging_dir}/{name}/`) are **not** resolved anymore; their files stay on disk and can be cleaned with `python clean.py --legacy-flat`.

**Checkpoint format:** PEFT state dicts are remapped to kohya keys (`lora_unet_*`, `lora_te1_*`, `lora_te2_*`), converted to bf16, and saved with alpha scalars plus `modelspec.*` and `ss_*` metadata — directly loadable in ComfyUI or with kohya sd-scripts.

## Resuming from a checkpoint

Set `[training].resume_lora_path` to a LoRA `.safetensors` (or to a directory containing exactly one) and start a run. The weights are loaded into the wrapped UNet and both text encoders right after the LoRA adapters are created, before the accelerator prepares the models.

What carries over and what does not:

| Carried over | Restarts from zero |
| --- | --- |
| UNet / TE1 / TE2 LoRA weights (`lora_down`, `lora_up`) | Optimizer state (Schedule-Free AdamW on both the UNet and the TEs) |
| — | LR warmup (`te_warmup_steps`, `unet_warmup_steps`) |
| — | `global_step` / `epoch` counters, sample filenames, TensorBoard step axis |
| — | Dataset order (caption shuffle is reseeded per epoch) |

Because the counters restart, the run writes into its own `{output_dir}/{run_id}/` directory — resuming from a run that ended at step 300 does not overwrite that run's `{name}_s000300/`.

Rules and failure modes:

- `network_type` must match the checkpoint. The trainer reads `ss_network_type`; a file without that field is `standard`, unless `ss_network_args` has `conv_dim > 0` (kohya LoCon). A locon file into a standard wrap (or the reverse) raises `ValueError` before any weights load. A locon wrap also refuses a locon file that has no TE `mlp_fc1` / `mlp_fc2` keys (pre-MLP locon files). `train_start` runs the type check, so the dashboard fails without touching the GPU.
- `network_dim` / `network_alpha` must match the checkpoint's rank. Locon `conv_dim` must match `ss_network_args` when that field is present. A rank mismatch is rejected at startup with a message naming `network_dim` or `conv_dim`; a differing alpha only logs a warning (the checkpoint's alpha scalars are ignored — this run uses `network_alpha` / `conv_alpha`).
- Tensors in the checkpoint that this LoRA does not use (e.g. modules outside the current `network_type` targets) are counted and listed in the run log; if **no** tensor maps, the run refuses to start.
- TE1 keys saved today are `lora_te1_text_model_encoder_layers_*`. Files written before that spelling (`lora_te1_encoder_layers_*`) still resume.
- `train_start` (and the trainer itself) validates the path before doing any GPU work, so a missing or ambiguous path surfaces as an immediate error in the dashboard.
- Any kohya-format LoRA works as long as its type and rank match, including ones trained by other tools; `ss_steps` / `ss_epoch` metadata are only reported for information.

## Watching progress

- **Dashboard** (recommended): live metric cards, charts, progress bars, and sample gallery.
- **TensorBoard**: `tensorboard --logdir <logging_dir>`.
- **Runtime state**: `cat $XDG_RUNTIME_DIR/axltrainer/state.json` (or the equivalent resolved path).
- **Logs**: `tail -f <runtime_dir>/train.log` (trainer stdout/stderr; driver log noise is filtered by `start_train.sh`).

### Validation loss

Set `[training].val_split_percent = 0` to turn the feature off: nothing is held out, neither pass
runs, no validation scalar is written, and the run log says `Validation: off`. Otherwise the dataset
keeps `ceil(percent/100 × images)` images out of training — drawn once from the run's `seed` and the
folder contents, so the run's log line `Validation split: N/M images held out` is reproducible, and
each held-out image also removes its folder's `repeat` draws per epoch. The first validation step is
**step 1**, then one every `val_interval` steps (and never when it is `0`), and each of those runs
**two passes** over up to `val_sample_count` held-out images:

- pass 1 scores a fresh random subset — coverage over the run — and its mean goes to `Val/Loss`;
- the same points are averaged over the current epoch's validation points (the window rule
  `Train/Avg_Loss` uses) into `Val/Avg_Loss`;
- pass 2 scores a **fixed, mutually dissimilar** sample, chosen once from the held-out images by
  thumbnail similarity, and its mean goes to `Val/Fixed_Loss` — the same images every time, so this
  curve is the one to read for a trend.

All three scalars are written in one TensorBoard event, at the same step as `Train/Loss`, and the
Dashboard draws `Val/Avg_Loss` and `Val/Fixed_Loss` beside `Avg Loss` in the **Train / Avg Loss**
chart. The ctrl-click readout lists all three by their own names.

Images are scored per aspect-ratio bucket, and each group is chunked at `train_batch_size`, so **one
forward inside a pass never carries more images than a training step's own forward** — the pass
cannot peak above the step it lands on, and `val_sample_count` may be larger than the batch. The
reported value is the mean over the images actually scored (each chunk weighs by its image count).
The cap costs a little time: a pass becomes more, smaller forwards (measured at `train_batch_size = 1`,
an 8-image pass went from 1.28 s to 1.61 s; at batch 3 it is three forwards of ≤3 instead).

The passes add forward-only work to the step they land on, so `val_interval` and `val_sample_count`
are the cost knobs: measured on the author GPU a single 8-image pass costs about 1.5 s, which is
about **+16 %** per step at the shipped interval of 5 with one pass — so roughly twice that with
both — and about +46 % if the interval is set to 1 with 5 images. A direct measurement of the two-pass
pair at batch 1 (72 steps, interval 5, 8 images) came out at 786 → 1255 ms/step; the percentage scales
with the step cost, so the per-pass figure is the portable one. When `val_sample_count` is at least
the size of the held-out set, both passes score every held-out image, so `Val/Loss` and
`Val/Fixed_Loss` describe the same work and the fixed curve is simply the complete held-out mean. The
held-out images keep their
latents (the warm cache encodes them like any other image), and each pass runs with the modules in
eval mode, without gradients, and inside a forked RNG, so the training step's own loss and weights
are unchanged — measured, not assumed: `test/probe_val_loss_gpu.py` (numbers in
`doc/agent/tests.md`).

## Cleanup

A run leaves samples, TensorBoard logs, and checkpoints behind. The dashboard's **Reset** button only clears the `finished`/`error` state so a new run can start: it deletes nothing. The run keeps its LoRA checkpoints, its sample images and its TensorBoard logs, which is what makes it browsable in the run history afterwards.

Deleting a run's artifacts is `clean.py`, the only tool that removes a run's weights, scoped to **one run**:

```bash
python clean.py                    # interactive: lists run directories, asks which to clean
python clean.py --run rein_20260911_120000
python clean.py --legacy-flat      # old flat layout ({output_dir}/{name}_*, {logging_dir}/{name})
```

It removes (same helper as Reset, `trainer/cleanup.py`):

1. `{output_dir}/{run_id}/{name}_samples/` (generated samples included)
2. `{logging_dir}/{run_id}/`
3. Optionally (after an interactive confirmation) all `{output_dir}/{run_id}/{name}_*` checkpoint dirs.

The run directory itself is removed once it is empty. If no run directory can be resolved, Reset only clears the state — it does not touch legacy flat artifacts.

The latent cache is **not** deleted — it's reusable across runs.

## Notes and gotchas

- **One run at a time.** `train.lock` makes a second concurrent run fail immediately.
- **Stale state.** If a training process dies hard, the next status read reconciles the dead PID to `error` ("training process is no longer running"). Reset to clear.
- **Stop during sampling** keeps the already-saved step checkpoint; the partially-denoised image is discarded.
- **`sample_seed = 0`** gives each repeat a fresh random seed (printed to the log); set a fixed seed for reproducibility.
- **Schedule-Free optimizers** require `train()`/`eval()` mode toggling around sampling and saving (eval() is what puts the parameters back to the averaged weights); the code does this for both optimizers automatically.
- **One metric window per run.** Each run writes its own TensorBoard event directory, so the dashboard shows the current/latest run only; a resumed run starts a new curve at step 1 rather than continuing the old one.
- **`ui.py` is deprecated** and still reads the old flat paths, so it will not show runs written in the new layout.
