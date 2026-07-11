# Track 2 Submission Notes

Everything you need to fill in on the lablab.ai submission form.

## Project Title
**Track2 Captioner — a two-stage video-caption agent tuned for style-match**

## Short Description (≤ 200 chars)
> A grounded two-stage video captioner: Qwen3-VL extracts dense visual facts, Gemma-3-27B writes four styled captions, with strict JSON, fallbacks, and stress-bench validation.

## Current Submission Default

The Docker image currently defaults to the measured two-stage pipeline
(`CAPTION_ENGINE=pipeline`): Qwen3-VL-8B for grounded scene facts and
Gemma-3-27B for the four style rewrites. This profile is the best reliable
stress benchmark run so far (`scores_stress_gemma_v6.json`: final `0.969`).
The ensemble engine is retained as an opt-in premium path, not the default
submission engine.

## Architecture

The default Docker profile samples each clip into representative frames,
extracts grounded visual facts with Qwen3-VL-8B, then rewrites those facts into
the four required styles with Gemma-3-27B. Formal captions use deterministic
fact rendering where that improves grounding, while creative styles keep the
style model's voice under strict visual constraints.

## Optional premium ensemble
Each clip is sampled to keyframes, then **three frontier vision models observe
independently** — GPT-5.5, Gemini 3.1 Pro, and Claude Opus 4.5 — each returning
an exhaustive list of concrete visual details. A **writer (Opus 4.5)
cross-references all three lists**: a detail seen by 2+ models is high-confidence
and used; a specific claim from a single model is dropped unless corroborated.
It then writes the four required styles. Detection comes from the *union* of what
the models see; precision comes from *cross-model agreement*. Measured on the 15
official AMD sample clips (the judge's own distribution) via an adversarial vision
audit: **0.942 caption accuracy, ~14.8 verified visual details per caption, near-zero
contradictions**, ~3x the detail of any single model — and it recovers text no
single model reads correctly (e.g. a street sign) through model agreement.

The ensemble remains behind `CAPTION_ENGINE=ensemble` for premium experiments,
but it is not the default submission path.

## Long Description

Track 2 asks for *four captions in four distinct tones* per clip, judged on **accuracy** (does the caption match the video?) and **style match** (does it hit the target tone?). Our system optimises those two axes independently.

**Stage 1 — DESCRIBE.** We sample 10 frames (scene-change detection + uniform fill via FFmpeg) at 896px and, when enabled, extract a Whisper transcript. A single VLM call (Qwen3-VL-235B) returns rich scene-facts JSON driven by a per-subject detail checklist — people: hairstyle, jewelry, nail color, peripherals; animals: species and coat ("orange tabby"); streets: approximate counts, signage and its language, tree species. This anchors the *accuracy* score and gives captions their concrete detail.

**Stage 2 — STYLE ×4.** Four LLM calls run in parallel (`asyncio.gather`), each with a style-specific system prompt containing 4 few-shot examples drawn from different domains (garden / boulevard / office / kitchen — so the model doesn't overfit the guide's three example clips). Each prompt explicitly **bans the traits of the other three styles**: the sarcastic prompt bans exclamations and tech jargon, the humorous_non_tech prompt bans all technical vocabulary, and so on. This is what gives a clean *style match* score.

**Optional LoRA layer.** We fine-tune Gemma 3 (4B for dev, 27B for submission) via Unsloth on ~800 synthesised examples spanning the 8 evaluation categories (nature, urban, animals, people, sports, food, weather, technology). When a deployed LoRA id is passed via `STYLE_LORA`, all four style calls route to it — the base prompts stay compatible.

**Safety net.** The container never crashes: per-task timeout, retries with exponential backoff, multi-provider failover (OpenRouter → Groq → Fireworks), style filters with whole-word matching, repair-over-reject normalization (uncertainty fillers stripped, sentence-boundary truncation), grounded fallbacks, and Pydantic validation before `results.json` is written. No requested style is ever missing or blank. Every filter rule is guarded by `scripts/test_style_filter.py` in CI.

## Technology Tags
Docker, Python, Fireworks AI, Gemma 3, Qwen2.5-VL, FFmpeg, faster-whisper, LoRA, Unsloth, asyncio

## Category Tags
AI Agent, Video, Multimodal, Developer Tools

## What we use from AMD platforms
- **AMD Developer Cloud** — MI300X for training the LoRA (Unsloth, ROCm 6).
- **ROCm** — PyTorch runtime for the training script.
- **Fireworks AI** — inference for the VLM (Qwen2.5-VL 7B) and the style rewriter (Gemma 3 27B). This makes us eligible for the **Best Use of Gemma via Fireworks** and **Best Use of Gemma in Video Captioning** prize slots.

## Repo layout
- `app/` — container code (main / pipeline / prompts / frames / audio)
- `finetune/` — dataset builder + LoRA trainer + Fireworks deploy guide
- `eval/` — local LLM-Judge proxy + zero-cost self-check
- `scripts/` — build.sh, run_local.sh, smoke_test.sh, mock_run.py
- `Makefile` — `make smoke`, `make dataset`, `make train`, `make submit-check`

## What we chose NOT to do (and why)
- **We do not overfit the three example clips** — the guide explicitly warns that "agents that only work on the three example clips will score poorly". Our few-shots span unrelated domains, validation runs on 12 held-out stress clips, and we eradicated every hardcoded-fallback leak (whole-word matching + fallback scanner).
- **We do not commit credentials** — the repo is key-free. If the judging harness injects no env vars, the public image must be built from CI secrets and those keys must be rotated after judging.
- **We do not put skin color or animal eye color in captions** — hallucinated appearance details cost accuracy and safety points; they stay in `uncertain_details`.

## Reproduction (5 minutes)
```bash
export FIREWORKS_API_KEY=fw_xxx
make build          # docker buildx amd64
make run            # runs the container on the 3 example clips
make self-check     # zero-cost structural + ban validation
make judge          # LLM-Judge proxy for a real accuracy × style-match score
```

## Reference bonuses eligible (verified 2026-07-08)
| Prize | Amount | Reason we qualify |
|---|---|---|
| Track 2 prize | share of **$10,000** pool ($5k/$3k/$2k across tracks) | Optimised specifically for LLM-Judge accuracy × style-match (0.96+ on visual judge proxy, n=12) |
| Best Use of Gemma | share of **$6,000** across all tracks, human-judged on the dossier | Gemma-3-27B writes every scored caption; measured best-in-class style-match (0.983); LoRA path ready for MI300X |
