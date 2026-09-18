# Continuity Mac

Apple Silicon fork of [ComfyUI-Continuity](https://github.com/roadmaus/ComfyUI-Continuity).
It still drives ComfyUI core — MiniMax H3, LTX 2.5 and the still families —
on **Metal / MPS**. It does not replace the sampler with h3.c.

**NVIDIA / CUDA users:** this is not that pack. Install the original instead:
[roadmaus/ComfyUI-Continuity](https://github.com/roadmaus/ComfyUI-Continuity).

One node for AI video and stills. Write a prompt, attach media with `@`,
press Render. Everything is local open weights. The one thing that can talk
to the outside is the prompt refiner, and only if you point it at your own
server or provider — LM Studio, Ollama, or a hosted API with your key.

![A shot sampling, with the render beside it](docs/img/hero.png)

## Who this is for

- Apple Silicon Mac (M-series), ComfyUI Desktop or a local ComfyUI on MPS
- One Continuity install: this folder, named `continuity`

Do not install this beside the CUDA pack. The node ids are the same on
purpose (saved workflows keep loading), so two folders register the same
ids and **neither node shows up**.

## Install

In ComfyUI Desktop the custom-nodes folder is usually
`~/Documents/ComfyUI/custom_nodes`. Remove any existing Continuity /
MiniMax Creator folder first, then:

```
cd ~/Documents/ComfyUI/custom_nodes
git clone https://github.com/audiohacking/ComfyUI-Continuity-Mac continuity
```

The folder must be named `continuity`: ComfyUI serves the UI from
`/extensions/continuity/`. Restart ComfyUI. Search for **Continuity Mac**
and drop it on an empty canvas — that is the whole start. An optional
example graph is under `example_workflows/`.

Nothing to pip install.

Weights are not downloaded. Put files in ComfyUI's `models/` tree (or leave
them where they already are). A prestartup also registers the Hugging Face
hub cache and a sibling [h3-ws](https://github.com/lmangani/h3-ws) checkout
when those exist. Turbo on this fork offers **TaoMate** as a filename
preset (strength 0.8, Euler/simple, 3 steps). Leave attention
on **default**. See [docs/models.md](docs/models.md#apple-metal).

## What it does

### One node, one prompt

Drop the node, type, press Render. Files you attach get an `@` name and you
cite them in the sentence, so the prompt says which picture is the person and
which is the room. The pills under the box are the whole setup: duration,
aspect, resolution, the model, and a sampler row for when you want it.
[The node](docs/the-node.md) walks every control.

![The node in the simple view](docs/img/simple.png)

### References and the cast

A reference contributes what you say it contributes - the person, the place,
the look - and the same face can be saved once and brought back into any
piece by name. Two references cited in one prompt:

![Two references cited in a prompt](docs/img/mentions.png)

### The pre-stage

Video models eat stills: start frames, end frames, references. The pre-stage
is a second card on the same canvas that makes them, with any of the stills
families or H3 itself, and hands the result straight into the shot. One Queue
runs both; an untouched pre-stage doesn't re-render.

![The simple view on the pre-stage step](docs/img/simple-prestage.png)

### Timelines

Under the prompt: *Write the next shot*. Every shot on the strip is a whole
generation with its own prompt, references, LoRAs and even its own family - a
pre-stage on Krea 2 feeding start frames into shots on LTX 2.5 is one strip.
Seams carry picture and sound across the cut, or don't, independently.
[Timelines](docs/timeline.md).

### Chat

The other way in. A room where you say what you want - *a fox in a snowy wood
at dusk*, then *now a clip of it, she looks up*, then *bluer* - and the
refiner model writes the prompt and renders. Every picture and clip gets a
handle you can cite in the next line, so a still becomes a shot's first frame
by naming it. It is the same node underneath, on the same queue, and
everything lands in the same output folder. [Chat](docs/tools.md#chat).

![The chat room, before the first line](docs/img/chat.png)

### Tools

The wordmark opens a dashboard of tools that work over the piece: presets, a
ControlNet bench, a blockout bench for staging a scene out of boxes and
walking a camera through it, and an upscale bench. [Tools](docs/tools.md).

![The tool dashboard](docs/img/dashboard.png)

![The blockout bench](docs/img/blockout.png)

The style atlas is 941 looks captioned from real clips, applied as a prefix
to the prompt:

![The style atlas](docs/img/style-atlas.png)

## Where it is headed

The name is the goal. A single shot from an open video model is a solved
problem; a piece made of many shots that still looks like one piece is not.
Every continued shot comes out a little brighter and a little harder than the
one it continues, and after a handful of seams the strip has drifted somewhere
you never asked for. Most of the work now goes there: measuring the drift on
real strips rather than guessing, and pushing the number of shots a piece can
hold before it shows.

The other direction is getting the graph out of the way. The chat room and the
blockout bench are both ways of saying what you want without touching a pill,
and the pre-stage plus the timeline are what let one prompt become a scene.
There is no cloud in any of that, and there won't be: everything renders on
your hardware from weights you already have.

## Documentation

- [Getting started](docs/getting-started.md)
- [Model downloads](docs/models.md) - every file, and the folder it goes in
- [The node](docs/the-node.md) - prompting, references, the cast, Refine
- [Timelines](docs/timeline.md) - pieces with more than one shot
- [Model families](docs/families.md) - what each model can do
- [Tools](docs/tools.md) - chat, ControlNet, upscaling, presets, LoRAs
- [FAQ and troubleshooting](docs/faq.md)
- [Changelog](CHANGELOG.md) - what changed, release by release

## Models

| Family | Makes | Weights |
|---|---|---|
| MiniMax H3 | video with sound, and stills | [Comfy-Org/MiniMax-H3](https://huggingface.co/Comfy-Org/MiniMax-H3) |
| LTX 2.5 | video with sound | [Lightricks/LTX-2.5](https://huggingface.co/Lightricks/LTX-2.5) |
| Krea 2 | stills | [Comfy-Org/Krea-2](https://huggingface.co/Comfy-Org/Krea-2) |
| Ideogram 4.0 | stills | [Comfy-Org/Ideogram-4](https://huggingface.co/Comfy-Org/Ideogram-4) |
| Qwen Image Edit | stills, edited from a picture | [Comfy-Org/Qwen-Image-Edit_ComfyUI](https://huggingface.co/Comfy-Org/Qwen-Image-Edit_ComfyUI) |
| Flux 2 Klein | stills, edited from a picture | [Black Forest Labs](https://huggingface.co/black-forest-labs) |

See [docs/models.md](docs/models.md) for which files you need and where they go.
On this fork, turbo for H3 offers TaoMate
(`taomate_h3_3step_comfy.safetensors` in `models/loras`) at strength 0.8
and 3 steps; LightX2V and Tutu keep the family's quality counts.

There is also an optional **neural refiner**: NVIDIA's DLSS 5 neural renderer
as a material pass over finished stills and clips (skin, hair, fabric, contact
shadows), through the open-source [MLX-DLSS](https://github.com/iamwavecut/MLX-DLSS)
port, which travels with the pack. It is not an upscaler and it ships with
nothing of NVIDIA's — the weights are extracted from your own copy of the DLSS
DLL on the settings page. See [docs/tools.md](docs/tools.md#neural-refiner-dlss-5).

## Thanks

This pack is glue. The work underneath it belongs to other people:

- [ComfyUI-Continuity](https://github.com/roadmaus/ComfyUI-Continuity) by roadmaus - the node this fork is
- [ComfyUI](https://github.com/comfyanonymous/ComfyUI) by Comfy Org - every family here lives in core, this node drives them
- [h3-ws](https://github.com/lmangani/h3-ws) - which MiniMax-H3 files and LoRAs this Mac checkout already has
- [Lightricks](https://huggingface.co/Lightricks) - LTX 2.5, its IC-LoRAs, the duration head and the two-stage pipeline
- [ComfyUI-Spectrum-MiniMax-H3](https://github.com/xmarre/ComfyUI-Spectrum-MiniMax-H3) by xmarre - an accelerator on the sampler row
- [ComfyUI-MiniMaxH3-FirstBlockCache](https://github.com/duckyshell/ComfyUI-MiniMaxH3-FirstBlockCache) by duckyshell - an accelerator on the sampler row
- [ComfyUI-MiniMaxH3-TeaCache](https://github.com/Icyoung/ComfyUI-MiniMaxH3-TeaCache) by Icyoung - an accelerator on the sampler row
- [ComfyUI-KJNodes](https://github.com/kijai/ComfyUI-KJNodes) by Kijai - the live preview decoder, sage attention, the low vram pill
- [ComfyUI-MultiGPU](https://github.com/pollockjj/ComfyUI-MultiGPU) by pollockjj - the device chip on the weights popover
- [ComfyUI-GGUF](https://github.com/city96/ComfyUI-GGUF) by city96 - loads the `.gguf` files the weights popover offers
- [ComfyUI#15416](https://github.com/Comfy-Org/ComfyUI/issues/15416) by matlowai - the fix behind H3 single-frame stills
- [ComfyUI-MiniMaxH3_LatentUpscaler](https://github.com/Tr1dae/ComfyUI-MiniMaxH3_LatentUpscaler) by Tr1dae - pioneered the two-pass upscale our refine pass reimplements
- [Minimax_h3_latent_Upscaler](https://huggingface.co/LBH-123-AI/Minimax_h3_latent_Upscaler) by LBH-123-AI - the trained latent upscaler behind the refine's "trained" road; the network is re-implemented here, the weights are theirs (Apache-2.0)
- [ComfyUI-H3-FaceRefine](https://github.com/Carasibana/ComfyUI-H3-FaceRefine) by Carasibana, and zuanfilm's graph on it - worked out the face pass ours reimplements
- [ComfyUI-MAINodes](https://github.com/matlowai/ComfyUI-MAINodes) by matlowai - the Motion Lab de-rope, whose method and measured dials the motion fix reimplements
- [minimax-h3-style-atlas](https://github.com/hoodtronik/minimax-h3-style-atlas) by hoodtronik, over [minimax_h3_1k](https://huggingface.co/datasets/ostris/minimax_h3_1k) by ostris - the 941 looks on the style tab
- [taehv](https://github.com/madebyollin/taehv) by madebyollin - the tiny decoder behind the live preview
- [BiRefNet](https://github.com/ZhengPeng7/BiRefNet) by ZhengPeng7 - the matte behind every one-click cutout
- [ComfyUI-H3-PowerLoraStack](https://github.com/cicalooo/ComfyUI-H3-PowerLoraStack) by cicalooo - the H3-safe LoRA loader, vendored (Apache-2.0)
- [MLX-DLSS](https://github.com/iamwavecut/MLX-DLSS) by iamwavecut - the DLSS 5 refiner's inference and weight extraction, vendored (Apache-2.0)
- [ComfyUI-VDN-H3](https://github.com/Saganaki22/ComfyUI-VDN-H3) by Saganaki22 - the port behind the VDN-H3 pill, vendored (Apache-2.0)
- [ComfyUI-PlagueKind-Nodes](https://github.com/PlagueKind/ComfyUI-PlagueKind-Nodes) by PlagueKind - SLA sparse attention on the attention pill
- [OpenVDN](https://github.com/OpenVDN/vdn-minimax-h3) - Video Delta Net itself: the hybrid attention, the training and the stages the pill loads
- NVIDIA - the DLSS 5 neural renderer itself. Nothing of theirs ships here; the weights are extracted from your own driver DLL
- [ReDetail](https://github.com/Bambushu/redetail) by Bambushu - the graph and the measurements behind the ReDetail upscale
- [Minimax-H3-ComfyUI](https://huggingface.co/Alissonerdx/Minimax-H3-ComfyUI) by Alissonerdx - the guide LoRAs behind the guide pass, and the rig they run in; trained on [ostris](https://github.com/ostris)'s ai-toolkit fork with guide-latent support
- [Raylight](https://github.com/Karmabu/raylight) by Karmabu - H3 across two GPUs
- MiniMax - H3 itself, and the reference guide this pack's prompts are written to
- Krea, Ideogram, Black Forest Labs and the Qwen team - the four still families beside H3 and LTX 2.5
- Meta - SAM 3, behind click-to-select cutouts, the faces pass and the Matte tracing
- ByteDance - SeedVR2, the Restore backend on the upscale bench
- Depth Anything 3 and SDPose - the two model-backed tracings, both loaded through core
- alibaba-pai - the MiniMax-H3-Acc-LoRAs whose 32 output heads the accelerator reads
- TaoMate, larryvrh and lightx2v - the H3 distillation LoRAs behind turbo
- CiviMeta - the sidecar format the LoRA cards read

Every node pack on that list is optional: if one is installed, the matching
pills light up, and if it is not, they say what is missing. The models are
optional in the same way — none of them is downloaded for you, and nothing on
this list ships inside the pack except the three vendored libraries it names.

## License

[MIT](LICENSE). ComfyUI itself is GPL-3.0 and this pack imports it; if you
redistribute the two together rather than as a node pack people install
themselves, that combination is what the GPL has an opinion about.
