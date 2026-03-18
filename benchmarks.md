---
layout: default
title: GPU Performance Benchmarks
description: Comprehensive benchmarks for AI model deployment on consumer GPUs
permalink: /benchmarks/
---

# GPU Performance Benchmarks

<div style="max-width: 1200px; margin: 0 auto;">

{% include benchmark-card.html title="RTX 5080 - AWQ Quantization" slug="5080-feedback" preview="<p>Testing AWQ 4-bit quantization on RTX 5080 with Llama.cpp. Results show **2x speed increase** (18.2→41.7 tokens/s) with **52% VRAM reduction**.</p><table style='width:100%; border-collapse:collapse; margin-top:1rem;'>
<tr style='background:#f8f9fa;text-align:left'><th>Method</th><th>VRAM (GB)</th><th>Tokens/s</th></tr>
<tr><td>FP16</td><td>~84</td><td>18.2</td></tr>
<tr style='background:#f0fff4'><td>AWQ-4bit</td><td>~38</td><td>41.7 ⚡</td></tr>
</table>" %}

{% include benchmark-card.html title="Qwen 3.5 Model Performance" slug="qwen-analysis" preview="<p>Evaluating Qwen 3.5 for larger tasks and small projects using llama.cpp.</p><ul style='margin-top:1rem; line-height:2;'>
<li>9B GGUF model tested</li>
<li>Nemotron-3 Nano comparison: Blazing fast (705-1061 t/s)</li>
<li>VRAM efficiency analysis pending</li>
</ul>" %}

</div>

__________________
QWEN3.5
Summary| Very capable model perfect for larger tasks and small projects
Tool| llamaCPP
prompt speed|
t/s|
VRAM usage| 99% max
from| unsloth
type| 9B GGUF
__________________
Nemotron3 Nano
Summary| Blazing fast - pefect for rapid chats and time priority
Tool| llamaCPP
prompt speed| 941 // 7050 // 1061
t/s| 196 // 204
VRAM usage| 99% max
from| nvidia
type| 4B GGUF
___________________


