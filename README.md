<h1 align="center">Strata — V100 32GB Tesla Volta SM70</h1>

> ## 🚨 Strata-v100-32gb-tesla-volta-sm70
>
> **Encapsulate’s Tesla V100 32GB / Volta SM70 edition.**
> The runnable V100 source and build are on the [`v100-sm70`](https://github.com/Encapsulate/Strata/tree/v100-sm70)
> branch. This branch adds the SM70 `mma.m8n8k4` QSA prompt-attention kernel, below-SM80 FP16 prefill GEMM,
> V100 dispatch fixes, CUDA 12 build instructions, and an automatic V100 prefill safeguard. On SM70,
> `--prefill auto` selects the validated 2,048-token chunk because the generic 8,192-token chunk can exhaust
> the V100's 32GB runtime headroom and stall long prompts. **Start here:**
> [V100 setup tutorial](https://github.com/Encapsulate/Strata/tree/v100-sm70#nvidia-v100--volta-experimental).
> For the cross-client Harness/Hermes/Open WebUI anti-loop and thinking setup,
> see [Stable IQ1/IQ3 routes](docs/ANTI_LOOP_AND_HALLUCINATION_TUTORIAL.md).
>
> The default `main` branch remains the upstream-compatible general Strata line. For the Encapsulate V100 build,
> switch to `v100-sm70` before building:
>
> ```bash
> git clone --branch v100-sm70 https://github.com/Encapsulate/Strata.git
> ```

## 32 GB V100 results at a glance

These are measured local results on a **single Tesla V100-SXM2-32GB (Volta
SM70, driver 580.173.02)** using the Encapsulate `v100-sm70` build. Both
routes use a 131,072-token context, INT8 KV with 32,768 resident cells, MTP4,
and the V100-safe 2,048-token prefill chunk. Only one heavy route is resident
at a time. Both model IDs are exposed through the shared OpenAI-compatible
gateway used by DeepSeek Harness, Hermes, and Open WebUI.

| Route | Weights | VRAM resident | Realistic code-review result | Best use |
|---|---:|---:|---|---|
| `swift-1.5-iq3_xxs` | 75.97 GB / 70.75 GiB, IQ3_XXS | 30,630–31,994 MiB | 19.4 tok/s at 2.8K prompt; 29.4 tok/s at 6.4K; 8.5–11.5 decode tok/s | general reasoning, tools, long prompts |
| `qwen3.8-flash-next-coder-iq1_m` | 58.41 GB / 54.40 GiB, IQ1_M | 30,566 MiB | 19.6 tok/s at 2.8K prompt; 29.8 tok/s at 6.4K; 8.3–10.8 decode tok/s | code generation and editing |

The comparison above is the relatable workload: both models received the same
real Strata Python/CUDA/CMake repository excerpts and the same senior-maintainer
code-review task. Every request reported **0 reused prompt tokens**. Each
returned a bounded 384-token structured review. On this single V100, prompt
processing is effectively the same because the shared SM70 runtime, KV
streaming, and host/RAM path dominate; the Coder route is not magically 1,000+
tok/s for real agent prompts.

The earlier numbered-word measurements remain below as a controlled engine
probe only. They are not end-to-end agent throughput and should not be used to
predict chat or coding latency.

Coder qualification task: a typed, thread-safe Python TTL/LRU cache module
plus pytest tests. The 2,048-token output budget completed cleanly; 512- and
1,024-token runs were recorded as truncated output-cap tests. Swift was
measured with deterministic 9.1K/19.4K/39.9K-token repository-style prompts;
the first sample includes cold/cache effects and the longest sample reused a
cached prefix.

| Setting | Swift IQ3_XXS | Coder IQ1_M |
|---|---|---|
| Engine | Strata 0.1.31, SM70 build | Strata 0.1.31, SM70 build |
| Prefill | explicit `2048` | `auto` → validated `2048` |
| Context | `131072` | `131072` |
| KV | `int8`, 32,768 resident | `int8`, 32,768 resident |
| Speculative decoding | MTP4, min-p 0.5 | MTP4, min-p 0.5 |
| Vision | no | no |
| Model ID | `swift-1.5-iq3_xxs` | `qwen3.8-flash-next-coder-iq1_m` |

Detailed records: [Swift V100 benchmark](bench/results/2026-10-05-v100-sm70/README.md)
and [Coder IQ1_M coding benchmark](bench/results/2026-10-05-v100-coder-iq1m/README.md).

## Encapsulate V100 edition — read this first

This is the hardware-specific project for **one Tesla V100-SXM2 32GB GPU (NVIDIA Volta, compute capability SM70)**.
It is not a 5090, 5070, RTX 30/40/50, or generic gaming-PC configuration. The tested model and runtime are:

```text
GPU:       Tesla V100-SXM2-32GB / Volta SM70
Model:     swift-1.5-iq3_xxs
Context:   131,072 tokens
Prefill:   --prefill auto -> 2,048-token chunks on SM70
KV:        int8, 32,768 resident cells
Backend:   Encapsulate v100-sm70 branch and SM70 CUDA 12 build
```

The V100-specific work includes the `mma.m8n8k4` SM70 QSA prompt-attention kernel, below-SM80 FP16 prefill GEMM,
V100 dispatch fixes, the automatic safe-prefill cap, and the benchmark in this README. Your local DeepSeek Harness,
Open WebUI, and Hermes routes use this Strata backend at `http://127.0.0.1:18082/v1`.

### Controlled V100 engine probe — not agent throughput

Reference card: **Tesla V100-SXM2-32GB**, driver 580.173.02, 32,768 MiB VRAM, Strata 0.1.31, Swift
`swift-1.5-iq3_xxs`, 131,072-token context. Runtime flags:

```text
--expert-cache auto --prefill 2048 --spec 4 --spec-min-p 0.5
--kv int8 --kv-resident 32768 --max-context 131072
```

| Prompt words | Prompt tokens | Prompt ms | **Prefill tok/s** | Wall time | Decode tok/s |
|---:|---:|---:|---:|---:|---:|
| 2,048 | 9,142 | ~67,000 | **136** | 67.6 s | 1-token sample |
| 4,096 | 19,382 | ~22,000 | **881** | 22.6 s | 1-token sample |
| 8,192 | 39,862 | ~28,000 | **1,423** | 28.7 s | 1-token sample; cached prefix |

These are controlled prompt-prefill measurements from Strata `/metrics`, calculated as
`prompt_tokens / prompt_ms * 1000`; each request generated one token. The first request includes cold/cache/page
warmup. The model cold-load took about 198 seconds, used about 31,994 MiB VRAM and 59.1 GiB system RAM, and later
long prompts completed without the previous SM70 stall. The full methodology and reproducible commands are in the
[V100 benchmark record](bench/results/2026-10-05-v100-sm70/README.md).

### V100 benchmark — Coder IQ1_M coding scope

The same Tesla V100-SXM2-32GB was also qualified with the ISTA-DASLab
Qwen3.8-Flash-Next Coder IQ1_M release. This is a separate route from the
Swift IQ3_XXS benchmark above; both remain available through the local Strata
handoff gateway.

```text
Model ID:  qwen3.8-flash-next-coder-iq1_m
Weights:   58,408,584,928 bytes / 54.40 GiB, two GGUF shards
Context:   131,072 tokens
KV:        int8, 32,768 resident cells
GPU:       Tesla V100-SXM2-32GB, SM70, driver 580.173.02
Runtime:   Strata 0.1.31, --prefill auto (validated 2,048-token chunk), MTP4
```

The coding-scope probe used thinking disabled, temperature 0, and bounded
code-only responses. It tested a Python `OrderedDict` LRU cache, a TypeScript
async exponential-backoff retry helper with `AbortSignal`, and a Python
interval-merging function with validation and non-mutating sorting. All three
returned code satisfying the structural checks. The measured completion rates
were 14.7 tok/s for the combined LRU/retry probe and 10.3 tok/s for the
standalone interval-merging probe. These are coding-probe decode measurements,
not a general long-answer speed claim.

The reproducible Coder configuration and probe record are in
[the Coder IQ1_M V100 benchmark record](bench/results/2026-10-05-v100-coder-iq1m/README.md).
The direct coding-task qualification completed 1,855 tokens in 55.5 seconds
(33.5 tok/s), with a 157-token prompt and `finish_reason=stop`.

### V100 setup — the only setup section for this GPU

```bash
git clone --branch v100-sm70 https://github.com/Encapsulate/Strata.git
cd Strata
cmake -S . -B build-v100 -G Ninja -DCMAKE_BUILD_TYPE=Release \
  -DCMAKE_CUDA_COMPILER=/usr/local/cuda/bin/nvcc \
  -DCMAKE_CUDA_ARCHITECTURES=70 -DSTRATA_ENABLE_CUDA=ON \
  -DSTRATA_EXPERIMENTAL_SM60=ON -DSTRATA_BUILD_TESTS=OFF \
  -DSTRATA_NATIVE_EXPERTS=ON
ninja -C build-v100 strata
```

Use `--prefill auto`: on SM70 the source automatically selects the safe 2,048-token chunk. This is an internal
batch size, not a 2,048-token context limit; the full 131,072-token context remains available. Connect DeepSeek
Harness, Open WebUI, or Hermes to the shared gateway at `http://127.0.0.1:11435/v1` and select either
`swift-1.5-iq3_xxs` or `qwen3.8-flash-next-coder-iq1_m`. The gateway starts the matching Strata unit and prevents
both 32 GB routes from being resident simultaneously.

**Do not use the RTX benchmark tables, RTX VRAM guidance, or generic one-click setup below as V100 instructions.**
Use only the [V100 setup tutorial](#v100-quick-setup) and [V100 benchmark](#what-the-v100-benchmark-means).

---

## Upstream/general Strata reference — not the Encapsulate V100 configuration

<p align="center"><b>Run a 125-billion-parameter AI model on a normal gaming PC</b><br>
general RTX/Strata hardware · Windows or Linux · upstream reference only</p>

<p align="center"><a href="https://github.com/Niko1221/Strata/releases/download/v0.1.10/Pagoda.mp4"><img src="docs/media/pagoda-preview.webp" width="720" alt="A voxel pagoda garden that Strata's model wrote, running in the browser"></a><br>
<sub>A voxel pagoda garden, 1 shot prompt running on an RTX 5070 with Strata (IQ3_S, 128K context) ·
<a href="https://github.com/Niko1221/Strata/releases/download/v0.1.10/Pagoda.mp4">full video (49 s)</a></sub></p>

Strata runs **[Qwen3.8-Flash-Next](https://huggingface.co/Qwen/Qwen3.8-Flash-Next)** - a large, smart AI model that
normally needs a server - on your own PC. It writes its answers at **60-95 tokens per second** (a token is about ¾
of a word): faster than you can read.

- **Free and open source.**

> **Jump to:** [How fast?](#how-fast-is-it) · [Which model?](#which-model-should-i-pick) · [Install](#install) ·
> [Using it](#using-it) · [Problems?](#something-went-wrong) · [How it works](#how-does-it-work) ·
> [All the details](docs/DETAILS.md)

---

## How fast is the upstream/general Strata reference?

The following numbers are measured on an RTX 5070, not on the Tesla V100 and not on the Encapsulate V100 runtime:

| Size | Writes answers (short chat) | Writes answers (128K context) | Reads your prompt |
| --- | ---: | ---: | ---: |
| **Q2_0** | 93 tokens/s | 74 tokens/s | 2,170 tokens/s |
| **IQ2_XS** | 79 tokens/s | 63 tokens/s | 2,090 tokens/s |
| **IQ3_XXS** | 62 tokens/s | 49 tokens/s | 1,750 tokens/s |
| **IQ3_S** | 53 tokens/s | 46 tokens/s | 1,620 tokens/s |
| **Coder** (IQ1_M) | 55 tokens/s | 43 tokens/s | 2,180 tokens/s |

- **Writes answers** = how fast the reply appears (tokens per second).
- **Reads your prompt** = how fast it takes in what you send (long documents, code, chat history), measured on a
  32K-token prompt; a 4K prompt reads at 910-1,580 tokens/s. A 32K prompt takes about 15 seconds with Q2_0.

A card with more VRAM is faster, because more of the model fits on the GPU: an RTX 3090 (24 GB) should do roughly
100-140 tokens per second. All measurements, long-context numbers and estimates for other cards are in the
[details](docs/DETAILS.md#speed-measured).

Every PC is different: `START-HERE.bat --calibrate` measures a few engine settings on yours and keeps the fastest
(about 5-10 minutes; on the PC above it made the Coder 7% faster).

Measured Strata on your own PC? See [Community benchmark results](docs/COMMUNITY_BENCHMARKS.md)
for a report template and how to share your results in a pull request.

**Two or three NVIDIA cards?** Just run `START-HERE.bat`: it lists your cards, says which ones Strata can use, and
asks whether to share the model across them (recommended when two can). An install made on one card asks once at
its next start. Or choose yourself: `START-HERE.bat --gpus 0,2` (both, remembered), `--gpus all`, or `--gpu 0` (one
card, this start only). Each card keeps the experts of its own layers, and prompts flow through the cards in a
pipeline: on an RTX 5080 + RTX 3090 prompts were read 18-20% faster than on the 5080 alone, decoding on par.
Every card must be an RTX 20 series or newer with 8 GB or more. See [docs/MULTI_GPU.md](docs/MULTI_GPU.md).

## Which model should I pick?

**The size** (the same model, compressed more or less):

| Model | RAM+VRAM Requirements | Speed | Quality |
| --- | ---: | --- | --- |
| **Q2_0** | 37.6 GB | fastest | good |
| **IQ2_XS** | 39.2 GB | fast | better (**recommended**) |
| **IQ3_XXS** | 47.0 GB | slower | great |
| **IQ3_S** | 54.8 GB | slowest | best: matches the full model on the published tests (original model only) |

**Will it fit?** Shard 1 is the part of the model that gets loaded when it starts: its experts go into your **RAM**,
the rest onto your graphics card (the second shard, a 29 GB lookup table, stays on the SSD). So it fits when your
**RAM is at least shard 1 + about 10 GB** for Windows and your other programs. With 64 GB of RAM every size fits
(IQ3_S with little else open); with 48 GB, Q2_0 and IQ2_XS. A bigger graphics card makes it faster, but it doesn't
lower the RAM needed.

**The version:**

- **Qwen3.8-Flash-Next** - the original.
- **[Coder](https://huggingface.co/ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-Coder-GGUF)** - ISTA-DASLab's coding
  version: half of the experts removed, keeping the ones that code, tool use and images need (91% of the full model's
  SWE-bench Verified score, 99% of LiveCodeBench, by its authors). One size (IQ1_M: its experts stored like IQ3_S):
  shard 1 is **29.6 GB**, so it fits a PC with **32 GB of RAM**, runs 262K context on 64 GB, and reads long prompts
  the fastest of all. Weaker outside coding.
- **[Swift 1.5](https://huggingface.co/ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF)** - a fine-tune by UkisAI
  that thinks much shorter before answering, so you get the answer sooner, with about the same quality. Same speed per
  token, and about the same RAM as the same size of the original (no IQ3_S). Its own license applies (see its page).

Not sure? Take **IQ2_XS** - or the **Coder** if you mainly write code, or have 32-48 GB of RAM. You can add another
one later with `SETUP.bat` (the same as `START-HERE.bat --setup`; on Linux `./setup.sh --setup`).

For **OrcaRouter's Flash-Next Uncensored IQ3_XXS**, see the [manual compatibility setup](docs/ORCA.md).
It needs an explicit packing conversion and is not an installer menu option.

### NVIDIA V100 / Volta (experimental)

This fork also carries an experimental CUDA 12 build for NVIDIA Volta (`sm_70`), including the V100 QSA prompt
attention path using `mma.m8n8k4` and the below-SM80 prefill GEMM path. It is not the normal RTX release build and
requires a CUDA 12.x toolkit; CUDA 13 does not generate `sm_70` code.

Build the V100 engine from the `v100-sm70` branch with:

```bash
cmake -S . -B build-v100 -G Ninja -DCMAKE_BUILD_TYPE=Release \
  -DCMAKE_CUDA_COMPILER=/usr/local/cuda/bin/nvcc \
  -DCMAKE_CUDA_ARCHITECTURES=70 -DSTRATA_ENABLE_CUDA=ON \
  -DSTRATA_EXPERIMENTAL_SM60=ON -DSTRATA_BUILD_TESTS=OFF \
  -DSTRATA_NATIVE_EXPERTS=ON
ninja -C build-v100 strata
```

The updated Volta attention series is compiled into the engine at commit `f9ee3f2` (the branch also includes the
V100 dispatch fix `aa86c49`). On V100, the automatic prompt selector now caps the chunk at the validated
`--prefill 2048` setting: the generic 8,192-token auto chunk can exhaust the V100's remaining runtime headroom and
stall the Volta prefill path on long prompts. Explicit larger chunks remain an experimental tuning option, not the
default. See [V100-SM70.md](V100-SM70.md) for the experimental support notes and limitations.
On the reference V100 system, the 40 GB expert load takes several minutes on a cold start; the service becomes
available only after the expert cache is resident.

Measured on the reference card: [Tesla V100 32GB / SM70 benchmark](bench/results/2026-10-05-v100-sm70/README.md).

#### What the V100 benchmark means

The reference machine is a **Tesla V100-SXM2-32GB** running driver 580.173.02, CUDA 12.x, Strata engine 0.1.31,
Swift `swift-1.5-iq3_xxs`, and a 131,072-token context. The active runtime flags were:

```text
--expert-cache auto --prefill 2048 --spec 4 --spec-min-p 0.5
--kv int8 --kv-resident 32768 --max-context 131072
```

| Prompt content | Strata prompt tokens | Wall time | Prompt rate | Outcome |
|---:|---:|---:|---:|---|
| 2,048 generated words | 9,185 | 65.1 s | 141 tok/s | completed; first/cold request effects |
| 4,096 generated words | 19,425 | 21.6 s | 899 tok/s | completed |
| 8,192 generated words | 39,905 | 27.4 s | 1,456 tok/s | completed |

These are prompt-processing measurements, not answer-generation speed: each test generated one token so the timing is
dominated by prefill. The first request pays startup, cache, and page-warmup costs; subsequent requests benefit from
resident experts and reusable prompt prefixes. The long-prompt tests completed without the previous SM70 stall.

`--prefill 2048` is the internal batch size used to process a long prompt. It does **not** reduce the context window
to 2,048 tokens, limit the conversation, or limit the answer. The service still supports 131,072 context tokens. The
smaller batch keeps temporary workspace within the V100's 32GB VRAM; the generic 8,192-token prefill batch can exhaust
that headroom and stall, even though an 8,192-token prompt itself works normally. The full reproducible run details
and binary hash are in the [benchmark record](bench/results/2026-10-05-v100-sm70/README.md).

#### V100 quick setup

This is a source package, not a bundled model download. You need:

- an NVIDIA V100/Volta GPU and a working NVIDIA driver (`nvidia-smi` must work);
- CUDA 12.x with `nvcc`, CMake, Ninja, a C++ compiler, and Python 3;
- the Strata model's GGUF files, tokenizer, packed model directory, MTP files, and expert profile;
- enough system RAM and SSD space for the selected model. The reference Swift IQ3_XXS setup loads about 40 GiB of
  experts and uses nearly all of a 32 GiB V100.

From a clean checkout:

```bash
git clone --branch v100-sm70 https://github.com/Encapsulate/Strata.git
cd Strata
cmake -S . -B build-v100 -G Ninja -DCMAKE_BUILD_TYPE=Release \
  -DCMAKE_CUDA_COMPILER=/usr/local/cuda/bin/nvcc \
  -DCMAKE_CUDA_ARCHITECTURES=70 -DSTRATA_ENABLE_CUDA=ON \
  -DSTRATA_EXPERIMENTAL_SM60=ON -DSTRATA_BUILD_TESTS=OFF \
  -DSTRATA_NATIVE_EXPERTS=ON
ninja -C build-v100 strata
```

Run the server by replacing the paths below with your model and pack paths:

```bash
./build-v100/strata --serve \
  --pack /path/to/pack \
  --native /path/to/model-shard-00001.gguf \
  --ple-gguf /path/to/model-shard-00001.gguf \
  --expert-profile /path/to/expert-profile.bin \
  --expert-cache auto --prefill auto \
  --spec 4 --spec-min-p 0.5 --mtp /path/to/mtp/rt \
  --max-context 131072 --kv int8 --kv-resident 32768
```

On SM70, `--prefill auto` now automatically selects the safe 2,048-token chunk. You do not need to add a separate
V100 flag. The 131,072-token context remains available; prefill chunk size only controls how a long prompt is split
while it is being processed. The first start can take several minutes while the expert arena and GPU cache load.

Verify the server before connecting a frontend:

```bash
curl http://127.0.0.1:18082/health
curl http://127.0.0.1:18082/v1/chat/completions \
  -H 'Content-Type: application/json' \
  -d '{"model":"swift-1.5-iq3_xxs","messages":[{"role":"user","content":"Say hello"}],"max_tokens":32}'
```

For DeepSeek Harness or Open WebUI, use the OpenAI-compatible base URL `http://127.0.0.1:18082/v1` and model
`swift-1.5-iq3_xxs`. For Hermes, use the same base URL and model. Keep only one heavy model resident on the V100;
switching to the Ollama Swift Q5 model requires stopping Strata first because both models do not fit together.

#### Credits and attribution

This V100 build is an Encapsulate-maintained integration branch of [Strata](https://github.com/Niko1221/Strata) by
Niko1221. The Volta work incorporates upstream contributions by Niko1221 and Klaus Friedel, including the SM70
`mma.m8n8k4` prompt-attention kernel, below-SM80 prefill GEMM path, and related older-GPU support. Encapsulate added
the V100 integration, build documentation, and the SM70 automatic-prefill safety cap. See the Git history for the
full author and commit record; upstream licenses and notices remain in this repository.

An **AMD Radeon RX 7900 XT / XTX, RX 9070 / 9070 XT or Radeon AI PRO R9700 on Linux** works too (experimental; the
RX 7800 XT / 7700 XT and RX 9060 XT were validated by their owners):
`./setup.sh --backend hip`, chosen by itself on a PC with no NVIDIA card Strata can use. It installs ROCm without sudo
and compiles the engine (no images yet; several cards with `--gpus`). Details: [AMD HIP](docs/AMD_HIP.md).

## Install

**You need:** an NVIDIA RTX 20, 30, 40 or 50 card with 12 GB of VRAM or more (RTX 20 since 0.1.27), enough RAM for the size you pick (above;
a big GPU makes up for less RAM - the [low-RAM mode](docs/DETAILS.md)),
~80 GB of free disk space (an SSD makes the first start much faster), and Windows 10/11 or Linux. The only thing you
install yourself is a current **NVIDIA driver** ([nvidia.com/drivers](https://www.nvidia.com/drivers) or the NVIDIA
App). Everything else - Python, the engine, the model - is set up for you.

**Windows**

1. [Download this project](https://github.com/Niko1221/Strata/archive/refs/heads/main.zip) and unzip it (or `git clone` it).
2. Double-click **`START-HERE.bat`**.
3. Answer a few questions - or just press Enter each time for the recommended choice:
   - **Which model and size?** The original or Swift 1.5, and Q2_0, IQ2_XS, IQ3_XXS or IQ3_S - see [above](#which-model-should-i-pick)
   - **How much context?** How much text it can keep in mind at once (it suggests one for your card). 384K and
     512K (experimental) extend the model past its trained 262K by rope scaling - the setup turns it on itself (yarn and a
     covering factor; `--rope-scaling`/`--rope-scale` override) ([details](docs/DETAILS.md))
   - **Images?** Whether it should also read pictures
   - **Experimental speed projection?** Off unless you say yes - [read what it does](docs/DETAILS.md#experimental-speed-projection-experimental-off-by-default) first

Then it downloads everything (the model is ~70 GB, so the first time takes a while - you can stop and it picks up
where it left off) and **starts the model**. Your browser opens the Strata app at `http://127.0.0.1:8080`.

> **While the model starts, your PC can be slow or stop responding for 1-3 minutes** (longest the first time): Strata
> loads 35-55 GB into your RAM and locks part of it for the graphics card. That's normal - wait, and don't close the
> window. The window tells you what it is doing.

**Next time**, just double-click `START-HERE.bat` again: it starts right away, nothing is downloaded twice. Close its
window to stop the model.

**Updating:** download the new version and unzip it anywhere (or `git pull`), then run `START-HERE.bat` in it. The
model files are kept in a `Strata-data` folder next to your Strata folder, so a new copy finds them and sets itself up
the same way - nothing big is downloaded again.

**Linux:** run `./setup.sh` - same questions, same result.

**Docker (Linux):** the same idea, in a container.

1. Host: Docker with the [NVIDIA Container Toolkit](https://docs.nvidia.com/datacenter/cloud-native/container-toolkit/latest/install-guide.html)
   and a driver **580 or newer** (CUDA 13.0).
2. Build (this compiles the engine into the image, so the container never compiles):
   `docker build -t strata .`
   `docker build -t strata --build-arg CUDA_ARCHITECTURES=89 .` builds for one card only (faster).
   The default covers RTX 30 (86), RTX 40 (89), RTX 50 (120) and A-series (80); a card outside that
   set needs a rebuild with its own arch. Add `--build-arg BUILD_VISION=0` to skip the image encoder.
3. Run (the first start downloads the ~70 GB model, then starts; later starts go straight to serving):
   `docker run --rm --gpus all -p 8080:8080 --ulimit memlock=-1 -v strata-data:/data strata`

   The setup choices are env vars: `-e MODEL=IQ2_XS -e FAMILY=qwen -e CONTEXT=32768 -e VISION=no`
   (or `MODEL=Q2_0|IQ3_XXS|IQ3_S`, `FAMILY=swift|coder`; the defaults above are the recommended ones).
   `-e VISION=cpu` keeps the image encoder on the CPU. `-e KV=int8|q4_0|k8v4` picks the KV cache
   precision; `k8v4` is INT8 K with 4-bit V and keeps its KV in VRAM from 64K up.
   Only the model files, the prepared pack, the MTP layer and the install config live in the
   `strata-data` volume; the engine is part of the image. Switching between models already on the
   volume needs no setup pass: `-e MODEL=Q2_0 -e FAMILY=coder` picks that model's config. Add
   `-e REINSTALL=1` only to change settings for a model already set up (context, vision, KV, host,
   api_key, LOW_RAM), since those are recorded in its config.
   Strata loads 32-62 GB into RAM. `--gpus all` on a host with two usable cards takes both: the
   layer split is setup's recommended default ([docs/MULTI_GPU.md](docs/MULTI_GPU.md)), and a volume
   set up for one card switches to the pair on its first start there. Pin one card with `-e GPU=0`,
   or name them with `-e GPUS=0,2` and where the later card's layers start with `-e LAYER_SPLIT=18`.
   A memory limit needs `-e LOW_RAM=on`, which maps the model's experts from the pack instead of
   keeping them in RAM: setup.py measures the host's RAM, not the container's limit, so it cannot
   see a cap. LOW_RAM runs on one card.
   The server listens on `0.0.0.0:8080` by default; set `-e API_KEY=<secret>` before exposing the port
   to a network. The image has a `HEALTHCHECK` on `/health`, so `docker ps` shows the container
   healthy once the model is loaded, and `GET /v1/status` says what it is running.

## Using it

<p align="center"><img src="docs/media/runpagoda.png" width="900" alt="The Strata app's Monitor tab next to a coding agent"><br>
<sub>The Strata app's <b>Monitor</b> (left) while a coding agent writes the pagoda garden from the video (right)</sub></p>

- **In the browser:** `http://127.0.0.1:8080` - the Strata app (it opens by itself when the model starts): **Chat**, a
  live **Monitor** of the model and your GPU/CPU/RAM, and **About** with the settings and addresses.
- **Chat in the terminal:** `.venv\Scripts\python chat.py`
- **Your apps and coding agents:** add it as an "OpenAI-compatible" provider with base URL
  **`http://127.0.0.1:8080/v1`**, any API key and any model name. Apps that use Anthropic's API: `http://127.0.0.1:8080/v1/messages`.
- **Thinking:** the model thinks before it answers. Choose **off, low, medium or high** - in the chat page menu, with
  `/think low` in `chat.py`, or with your app's "reasoning effort" setting. Off is fastest; high is best for hard questions.
- **Pictures:** in the chat page click **Picture**; in `chat.py` type `/image <path>`; in apps just attach them.
- **From your phone or another PC:** `START-HERE.bat --setup --host 0.0.0.0 --api-key <secret>`, then open the
  address the server window prints; see the [details](docs/DETAILS.md#using-it).
- **Experimental speed projection (off by default):** an experimental control vector that setup can turn on; it
  changes how the model answers - read [what it does](docs/DETAILS.md#experimental-speed-projection-experimental-off-by-default) first.

**Good to know:** it answers one request at a time. The first message of a chat is read in full (about 1 minute per
30,000 tokens); after that it keeps the conversation and reads only what is new, so follow-ups start in seconds.

### Where things are stored

- **Your chats: only in your browser.** The Chat tab keeps the conversation, its settings and the API key you typed
  in the browser's local storage (`strata.*` keys) - not on the server and not in the Strata folder. Pictures are not
  kept, only their names. Another browser or a private window starts empty; clearing the site's data deletes them.
- **How the model starts:** `strata-<model>.json` in the Strata folder (context, GPUs, host, API key, ...), written
  by setup; next to it `run-<model>.bat` / `.sh`, the log `strata-<model>.log` and, when you use "Use for other
  apps too", `strata-<model>.shared-settings.json`.
- **The model files** (`models/`, `packs/`, `mtp/`, 70-120 GB): in **`Strata-data` next to the Strata folder**, or
  wherever `--data-dir` put them.
- **Where that data folder is:** `%APPDATA%\Strata\settings.json` on Windows, `~/.config/strata/settings.json` on
  Linux ([details](docs/DETAILS.md)).

## Something went wrong?

**My PC froze, or got very slow, the first time Strata started.**
That's normal while it starts, most of all the first time. Strata loads 35-55 GB into your RAM, locks part of it for
the graphics card, and works out how much of the model fits on your GPU. The mouse can freeze for a few minutes. **Wait, and don't close the
window.** The next starts are much faster. Still frozen after 10 minutes? Restart the PC, close other programs
(browsers use a lot of RAM) and try again. If it keeps happening, pick a smaller size (Q2_0 or IQ2_XS).

**It stopped while downloading or installing.**
Run `START-HERE.bat` again. It continues where it stopped.

**It says the NVIDIA driver is too old.**
Update it (NVIDIA App or [nvidia.com/drivers](https://www.nvidia.com/drivers)), restart the PC, and run
`START-HERE.bat` again.

**It says port 8080 is already in use.**
Strata is already running. Look for its window.

**It's very slow and the disk light keeps blinking.**
Your PC is out of free RAM. Close other programs, or pick a smaller size (Q2_0 or IQ2_XS).

**An answer stopped with "the engine stopped unexpectedly".**
Usually not enough RAM (on Linux the system then stops the engine). Just send your message again: Strata starts the
engine by itself. If it keeps happening, close other programs or pick a smaller size.

**It says the prompt exceeds the context.**
The conversation is longer than the context you chose. Start a new chat, or run `SETUP.bat` and pick more
context.

**Still stuck?** Look in the [full troubleshooting table](docs/DETAILS.md#troubleshooting), or open an issue and
attach `strata-<model>.log` from the Strata folder.

## How does it work?

Models like this one normally run on servers with hundreds of gigabytes of graphics memory. Your graphics card has
12-24 GB. Strata makes it fit by **sharing the work across your whole PC** - the same idea as a kitchen, where the
things you use all the time stay on the counter and the rest waits in the pantry.

<p align="center"><img src="docs/media/how-it-works.svg" width="860" alt="The model's 24,576 experts: the busiest on the graphics card, all of them in RAM, a lookup table on the SSD"></p>

- **The model is a team of 24,576 small specialists ("experts"),** and each word it writes needs only 10 of them.
  So it doesn't have to have all of them on the graphics card at once.
- **Your graphics card** does the part of the work needed for every word, and keeps the few thousand experts that
  are asked most often. It keeps learning which ones those are while you use it.
- **Your RAM** holds every expert. When a word needs one the card doesn't have, **your processor** works on it -
  at the same time as the graphics card, so neither waits for the other.
- **Your SSD** holds a big lookup table; the model only reads a few small rows of it per word.

<p align="center"><img src="docs/media/guess-and-check.svg" width="860" alt="A small helper guesses the next words; the big model checks them all at once and keeps the right ones"></p>

- **Guess, then check.** A small, fast helper built into the model guesses the next few words, and the big model
  checks all the guesses in one go. It keeps the ones it agrees with and writes the next word itself - so one step
  often produces several words. The helper only guesses - the big model decides every word - so you get the same
  quality answer, 1.6-1.8x sooner.
- **Long texts are read in big pieces** (up to 8,192 tokens - pieces of words - at a time), which is why a long
  document or code base is read at over 1,000 tokens per second.

Want the full picture? The [details](docs/DETAILS.md#how-it-works) explain every part and its numbers, and the
[paper](docs/paper/Strata-Paper.pdf) tells the whole story, with the measurements behind it.

## Credits

- Model: [Qwen3.8-Flash-Next](https://huggingface.co/Qwen/Qwen3.8-Flash-Next) by the Qwen team; compressed versions by
  [ISTA-DASLab](https://huggingface.co/ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF);
  [Swift 1.5](https://huggingface.co/ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF) by UkisAI. Their licenses apply
  to the model files.
- Built with parts of [llama.cpp / ggml](https://github.com/ggml-org/llama.cpp) (MIT). Ideas from
  [Splash](https://github.com/incoai/splash), [ninfer](https://github.com/Neroued/ninfer) and
  [HyperQwen](https://github.com/syv-ai/HyperQwen). More in the [details](docs/DETAILS.md#credits-and-licenses).

## License

Strata is open source under the [MIT License](LICENSE). A few parts carry their own licenses: `third_party/ggml`
(MIT, llama.cpp / ggml), the web app's font (SIL Open Font License 1.1) and the experimental speed projection's
vector in `data/experimental-speed-projection` (Qwen Community License 1.0, from the model's activations). The
models are not part of this repository; each model's own license applies to its files.
