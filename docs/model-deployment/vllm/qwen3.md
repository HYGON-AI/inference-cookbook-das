# Qwen3 on vLLM

## 模型简介

Qwen3 是阿里通义千问第三代大语言模型，支持 0.6B ~ 235B 多种参数规模，原生支持思考模式（thinking mode）和工具调用。

## 模型列表

| 模型权重 | 量化方式 | vLLM 版本 | 推荐硬件 | 卡数 | 部署方式 | 启动命令 |
| -------- | -------- | --------- | -------- | ---- | -------- | -------- |
| [Qwen/Qwen3-0.6B](https://www.modelscope.cn/models/Qwen/Qwen3-0.6B) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1000-1x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-k100_ai-1x-vllm-021) |
|  | BF16 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1100-1x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1000-1x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | K100_AI | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-k100_ai-1x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1000-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-k100_ai-1x-vllm-018-hotfix) |
|  | BF16 | 0.15 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-06b-ifb-bw1000-1x-vllm-015) |
| [Qwen/Qwen3-1.7B](https://www.modelscope.cn/models/Qwen/Qwen3-1.7B) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-bw1000-1x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-k100_ai-1x-vllm-021) |
|  | BF16 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-bw1100-1x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-bw1000-1x-vllm-018) |
|  | BF16 | 0.18 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-k100_ai-1x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-bw1000-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 1 | IFB | [**`>_`**](#qwen3-17b-ifb-k100_ai-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-4B](https://www.modelscope.cn/models/Qwen/Qwen3-4B) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-bw1000-1x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-k100_ai-1x-vllm-021) |
|  | BF16 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-bw1100-1x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-bw1000-1x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | K100_AI | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-k100_ai-1x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-bw1000-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 1 | IFB | [**`>_`**](#qwen3-4b-ifb-k100_ai-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-4B-Channel-INT8-w8a8](https://www.modelscope.cn/models/hygon/Qwen3-4B-Channel-INT8-w8a8) | INT8 W8A8 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-channel-int8-w8a8-ifb-bw1100-1x-vllm-021) |
|  | INT8 W8A8 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-channel-int8-w8a8-ifb-bw1000-1x-vllm-021) |
|  | INT8 W8A8 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-channel-int8-w8a8-ifb-bw1100-1x-vllm-018) |
|  | INT8 W8A8 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-channel-int8-w8a8-ifb-bw1000-1x-vllm-018) |
|  | INT8 W8A8 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-channel-int8-w8a8-ifb-bw1100-1x-vllm-018-hotfix) |
|  | INT8 W8A8 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-channel-int8-w8a8-ifb-bw1000-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-4B-Thinking-2507](https://www.modelscope.cn/models/Qwen/Qwen3-4B-Thinking-2507) | BF16 | 0.21 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-4b-thinking-2507-ifb-k100ai-1x-vllm-021) |
|  | BF16 | [0.18](../docker_images.md) | BW1100 | 1 | IFB | [**`>_`**](#qwen3-4b-thinking-2507-ifb-bw1100-1x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | BW1000 | 1 | IFB | [**`>_`**](#qwen3-4b-thinking-2507-ifb-bw1000-1x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | K100_AI | 1 | IFB | [**`>_`**](#qwen3-4b-thinking-2507-ifb-k100ai-1x-vllm-018) |
| [Qwen/Qwen3-8B](https://www.modelscope.cn/models/Qwen/Qwen3-8B) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-bw1000-1x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-k100_ai-1x-vllm-021) |
|  | BF16 | [0.18](../docker_images.md) | BW1100 | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-bw1100-1x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | BW1000 | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-bw1000-1x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | K100_AI | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-k100_ai-1x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-bw1000-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 1 | IFB | [**`>_`**](#qwen3-8b-ifb-k100_ai-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-8B-Channel-INT8-w8a8](https://www.modelscope.cn/models/hygon/Qwen3-8B-Channel-INT8-w8a8) | INT8 W8A8 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-8b-channel-int8-w8a8-ifb-bw1100-1x-vllm-021) |
|  | INT8 W8A8 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-8b-channel-int8-w8a8-ifb-bw1000-1x-vllm-021) |
|  | INT8 W8A8 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-8b-channel-int8-w8a8-ifb-bw1100-1x-vllm-018) |
|  | INT8 W8A8 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-8b-channel-int8-w8a8-ifb-bw1000-1x-vllm-018) |
|  | INT8 W8A8 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-8b-channel-int8-w8a8-ifb-bw1100-1x-vllm-018-hotfix) |
|  | INT8 W8A8 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-8b-channel-int8-w8a8-ifb-bw1000-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-14B](https://www.modelscope.cn/models/Qwen/Qwen3-14B) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-bw1000-1x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-k100_ai-1x-vllm-021) |
|  | BF16 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-bw1100-1x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-bw1000-1x-vllm-018) |
|  | BF16 | 0.18 | K100_AI | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-k100_ai-1x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-bw1000-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 1 | IFB | [**`>_`**](#qwen3-14b-ifb-k100_ai-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-14B-Channel-INT8-w8a8](https://www.modelscope.cn/models/hygon/Qwen3-14B-Channel-INT8-w8a8) | INT8 W8A8 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-14b-channel-int8-w8a8-ifb-bw1100-1x-vllm-021) |
|  | INT8 W8A8 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-14b-channel-int8-w8a8-ifb-bw1000-1x-vllm-021) |
|  | INT8 W8A8 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-14b-channel-int8-w8a8-ifb-bw1100-1x-vllm-018) |
|  | INT8 W8A8 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-14b-channel-int8-w8a8-ifb-bw1000-1x-vllm-018) |
|  | INT8 W8A8 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-14b-channel-int8-w8a8-ifb-bw1100-1x-vllm-018-hotfix) |
|  | INT8 W8A8 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-14b-channel-int8-w8a8-ifb-bw1000-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-32B](https://www.modelscope.cn/models/Qwen/Qwen3-32B) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-32b-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 2 | IFB | [**`>_`**](#qwen3-32b-ifb-bw1000-2x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 2 | IFB | [**`>_`**](#qwen3-32b-ifb-k100_ai-2x-vllm-021) |
|  | BF16 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-32b-ifb-bw1100-1x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 2 | IFB | [**`>_`**](#qwen3-32b-ifb-bw1000-2x-vllm-018) |
|  | BF16 | 0.18 | K100_AI | 2 | IFB | [**`>_`**](#qwen3-32b-ifb-k100_ai-2x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-32b-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 2 | IFB | [**`>_`**](#qwen3-32b-ifb-bw1000-2x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 2 | IFB | [**`>_`**](#qwen3-32b-ifb-k100_ai-2x-vllm-018-hotfix) |
| Qwen3-32B.w8a8 | INT8 W8A8 | 0.21 | K100_AI | 4 | IFB | [**`>_`**](#qwen3-32bw8a8-ifb-k100_ai-4x-vllm-021) |
|  | INT8 W8A8 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-32bw8a8-ifb-bw1100-1x-vllm-018) |
|  | INT8 W8A8 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-32bw8a8-ifb-bw1000-1x-vllm-018) |
|  | INT8 W8A8 | 0.18 | K100_AI | 4 | IFB | [**`>_`**](#qwen3-32bw8a8-ifb-k100_ai-4x-vllm-018) |
| [Qwen/Qwen3-30B-A3B-Instruct-2507](https://www.modelscope.cn/models/Qwen/Qwen3-30B-A3B-Instruct-2507) | BF16 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1100-1x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1000-2x-vllm-021) |
|  | BF16 | 0.21 | K100_AI | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-k100_ai-2x-vllm-021) |
|  | BF16 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1100-1x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1000-2x-vllm-018) |
|  | BF16 | 0.18 | K100_AI | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-k100_ai-2x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1100-1x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1000-2x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | K100_AI | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-k100_ai-2x-vllm-018-hotfix) |
|  | BF16 | 0.15 | BW1000 | 2 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-ifb-bw1000-2x-vllm-015) |
| [Qwen/Qwen3-30B-A3B-Channel-INT8-w8a8](https://www.modelscope.cn/models/hygon/Qwen3-30B-A3B-Channel-INT8-w8a8) | INT8 W8A8 | 0.21 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-w8a8-int8-ifb-bw1100-1x-vllm-021) |
|  | INT8 W8A8 | 0.21 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-w8a8-int8-ifb-bw1000-1x-vllm-021) |
|  | INT8 W8A8 | 0.18 | BW1100 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-w8a8-int8-ifb-bw1100-1x-vllm-018) |
|  | INT8 W8A8 | 0.18 | BW1000 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-w8a8-int8-ifb-bw1000-1x-vllm-018) |
|  | INT8 W8A8 | 0.18-hotfix | BW1100 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-w8a8-int8-ifb-bw1100-1x-vllm-018-hotfix) |
|  | INT8 W8A8 | 0.18-hotfix | BW1000 | 1 | IFB | [**`>_`**](#qwen3-30b-a3b-instruct-2507-w8a8-int8-ifb-bw1000-1x-vllm-018-hotfix) |
| [Qwen/Qwen3-235B-A22B-Instruct-2507](https://www.modelscope.cn/models/Qwen/Qwen3-235B-A22B-Instruct-2507) | BF16 | 0.21 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1100-4x-vllm-021) |
|  | BF16 | 0.21 | BW1000 | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1000-8x-vllm-021) |
|  | BF16 | [0.18](../docker_images.md) | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1100-4x-vllm-018) |
|  | BF16 | 0.18 | BW1000 | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1000-8x-vllm-018) |
|  | BF16 | 0.18-hotfix | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1100-4x-vllm-018-hotfix) |
|  | BF16 | 0.18-hotfix | BW1000 | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1000-8x-vllm-018-hotfix) |
|  | BF16 | 0.15 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1100-4x-vllm-015) |
|  | BF16 | 0.15 | BW1000 | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-bw1000-8x-vllm-015) |
|  | BF16 | 0.15 | K100_AI | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-instruct-2507-ifb-k100_ai-8x-vllm-015) |
| [Qwen/Qwen3-Next-80B-A3B-Instruct](https://www.modelscope.cn/models/Qwen/Qwen3-Next-80B-A3B-Instruct) | FP16 | 0.21 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-next-80b-a3b-instruct-ifb-bw1100-4x-vllm-021) |
|  | FP16 | 0.21 | BW1000 | 4 | IFB | [**`>_`**](#qwen3-next-80b-a3b-instruct-ifb-bw1000-4x-vllm-021) |
| [Qwen/Qwen3-Coder-480B-A35B-Instruct-FP8-Dynamic](https://www.modelscope.cn/models/Qwen/Qwen3-Coder-480B-A35B-Instruct-FP8-Dynamic) | FP8 | 0.21 | BW1100 | 8 | IFB | [**`>_`**](#qwen3-coder-480b-a35b-instruct-fp8-dynamic-ifb-bw1100-8x-vllm-021) |
| [Qwen/Qwen3-235B-A22B](https://www.modelscope.cn/models/Qwen/Qwen3-235B-A22B) | BF16 | [0.18](../docker_images.md) | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-ifb-bw1100-4x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | BW1000 | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-ifb-bw1000-8x-vllm-018) |
|  | BF16 | [0.18](../docker_images.md) | K100_AI | 8 | IFB | [**`>_`**](#qwen3-235b-a22b-ifb-k100_ai-8x-vllm-018) |
| [hygon/Qwen3-235B-A22B-Channel-INT8-w8a8](https://www.modelscope.cn/models/hygon/Qwen3-235B-A22B-Channel-INT8-w8a8) | INT8 W8A8 | 0.21 | BW1100 | 2 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1100-2x-vllm-021) |
|  | INT8 W8A8 | 0.21 | BW1000 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1000-4x-vllm-021) |
|  | INT8 W8A8 | 0.21 | K100_AI | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-k100_ai-4x-vllm-021) |
|  | INT8 W8A8 | 0.18 | BW1100 | 2 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1100-2x-vllm-018) |
|  | INT8 W8A8 | 0.18 | BW1000 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1000-4x-vllm-018) |
|  | INT8 W8A8 | 0.18 | K100_AI | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-k100_ai-4x-vllm-018) |
|  | INT8 W8A8 | 0.18-hotfix | BW1100 | 2 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1100-2x-vllm-018-hotfix) |
|  | INT8 W8A8 | 0.18-hotfix | BW1000 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1000-4x-vllm-018-hotfix) |
|  | INT8 W8A8 | 0.15 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-channel-int8-w8a8-ifb-bw1100-4x-vllm-015) |
| [Qwen/Qwen3-235B-A22B-FP8-Channel](https://www.modelscope.cn/models/hygon/Qwen3-235B-A22B-W8A8) | FP8 | 0.21 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-fp8-channelwise-ifb-bw1100-4x-vllm-021) |
|  | FP8 | 0.18 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-fp8-channelwise-ifb-bw1100-4x-vllm-018) |
|  | FP8 | 0.18-hotfix | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-fp8-channelwise-ifb-bw1100-4x-vllm-018-hotfix) |
|  | FP8 | 0.15 | BW1100 | 4 | IFB | [**`>_`**](#qwen3-235b-a22b-fp8-channelwise-ifb-bw1100-4x-vllm-015) |
## 启动命令

### Qwen3-0.6B IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-0.6B IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-0.6B IFB K100_AI 1x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend TRITON_ATTN
```

### Qwen3-0.6B IFB BW1100 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3
```

### Qwen3-0.6B IFB BW1000 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 
```

### Qwen3-0.6B IFB K100_AI 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code 
```

### Qwen3-0.6B IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-0.6B IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-0.6B IFB K100_AI 1x vLLM 0.18-hotfix

```bash

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-0.6B IFB BW1000 1x vLLM 0.15

```bash
export VLLM_USE_PIECEWISE=1

vllm serve Qwen/Qwen3-0.6B \
  -tp 1 \
  --trust-remote-code \
  --disable-log-requests \
  --dtype bfloat16 \
  --disable-cascade-attn \
  -cc '{"pass_config": {"fuse_act_quant": false}, "custom_ops": ["all"]}'
```

### Qwen3-1.7B IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-1.7B IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-1.7B IFB K100_AI 1x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend TRITON_ATTN
```

### Qwen3-1.7B IFB BW1100 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 
```

### Qwen3-1.7B IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 
```

### Qwen3-1.7B IFB K100_AI 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code
```

### Qwen3-1.7B IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-1.7B IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-1.7B IFB K100_AI 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-1.7B \
  -tp 1 \
  --trust-remote-code
```

### Qwen3-4B IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B IFB K100_AI 1x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-4B IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240
```

### Qwen3-4B IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 \
  --max-num-batched-tokens 10240
```

### Qwen3-4B IFB K100_AI 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-4B IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B IFB K100_AI 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-4B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-4B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-4B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-4B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-4B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-4B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-4B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-4B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-4B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-4B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-4B-Thinking-2507 IFB K100_AI 1x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-4B-Thinking-2507 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-4B-Thinking-2507 IFB BW1100 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-4B-Thinking-2507 \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240
```

### Qwen3-4B-Thinking-2507 IFB BW1000 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-4B-Thinking-2507 \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 \
  --max-num-batched-tokens 10240
```

### Qwen3-4B-Thinking-2507 IFB K100_AI 1x vLLM 0.18

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-4B-Thinking-2507 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240
```

### Qwen3-8B IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B IFB K100_AI 1x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-8B IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240
```

### Qwen3-8B IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 \
  --max-num-batched-tokens 10240 
```

### Qwen3-8B IFB K100_AI 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-8B IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B IFB K100_AI 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-8B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-8B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-8B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-8B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-8B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-8B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-8B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-8B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-8B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-8B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-8B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B IFB K100_AI 1x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-14B IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240
```

### Qwen3-14B IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 \
  --max-num-batched-tokens 10240
```

### Qwen3-14B IFB K100_AI 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-14B IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B IFB K100_AI 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-14B \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-14B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-14B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-14B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-14B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-14B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-14B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-14B-Channel-INT8-w8a8 IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-14B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-14B-Channel-INT8-w8a8 IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-14B-Channel-INT8-w8a8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-32B IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-32B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-32B IFB BW1000 2x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-32B \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-32B IFB K100_AI 2x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-32B \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-32B IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-32B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240
```

### Qwen3-32B IFB BW1000 2x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-32B \
  -tp 2 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e5m2 \
  --max-num-batched-tokens 10240
```

### Qwen3-32B IFB K100_AI 2x vLLM 0.18

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-32B \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-32B IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-32B \
  -tp 1 \
  --trust-remote-code \
  --kv-cache-dtype fp8_e4m3 \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-32B IFB BW1000 2x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-32B \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-32B IFB K100_AI 2x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-32B \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-32B.w8a8 IFB K100_AI 4x vLLM 0.21

```bash


export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen3-32B.w8a8 \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-32B.w8a8 IFB BW1100 1x vLLM 0.18

```bash
export VLLM_NUMA_BIND=1
export VLLM_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen3-32B.w8a8 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3
```

### Qwen3-32B.w8a8 IFB BW1000 1x vLLM 0.18

```bash
export VLLM_NUMA_BIND=1
export VLLM_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_RANK0_NUMA=1

vllm serve Qwen3-32B.w8a8 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240
```

### Qwen3-32B.w8a8 IFB K100_AI 4x vLLM 0.18

```bash

export VLLM_NUMA_BIND=1
export VLLM_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen3-32B.w8a8 \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1100 1x vLLM 0.21

```bash
vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM \
  --moe-backend aiter
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1000 2x vLLM 0.21

```bash
vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM \
  --moe-backend aiter
```

### Qwen3-30B-A3B-Instruct-2507 IFB K100_AI 2x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_ROCM_USE_AITER=1
export VLLM_ROCM_USE_AITER_MOE=1

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1000 2x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_ROCM_USE_AITER=1
export VLLM_ROCM_USE_AITER_MOE=1

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-30B-A3B-Instruct-2507 IFB K100_AI 2x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1
vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM \
  --moe-backend aiter
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1000 2x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1
vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend FLASH_ATTN_CUSTOM \
  --moe-backend aiter
```

### Qwen3-30B-A3B-Instruct-2507 IFB K100_AI 2x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507 \
  -tp 2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-30B-A3B-Instruct-2507 IFB BW1000 2x vLLM 0.15

```bash
export VLLM_USE_PD_SPLIT=0

vllm serve Qwen/Qwen3-30B-A3B \
  -tp 2 \
  --trust-remote-code \
  --dtype float16 \
  --disable-cascade-attn \
  -cc '{"pass_config": {"fuse_act_quant": false}, "custom_ops": ["all"]}'
```

### Qwen3-30B-A3B-Instruct-2507-W8A8-INT8 IFB BW1100 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507-W8A8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-30B-A3B-Instruct-2507-W8A8-INT8 IFB BW1000 1x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507-W8A8 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-30B-A3B-Instruct-2507-W8A8-INT8 IFB BW1100 1x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507-W8A8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin
```

### Qwen3-30B-A3B-Instruct-2507-W8A8-INT8 IFB BW1000 1x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507-W8A8 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin 
```

### Qwen3-30B-A3B-Instruct-2507-W8A8-INT8 IFB BW1100 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507-W8A8 \
  -tp  1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-30B-A3B-Instruct-2507-W8A8-INT8 IFB BW1000 1x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-30B-A3B-Instruct-2507-W8A8 \
  -tp 1 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --q slimquant_marlin \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1100 4x vLLM 0.21

```bash
export VLLM_ROCM_USE_AITER=0
export VLLM_ROCM_USE_AITER_MOE=0

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  -tp 4 \
  --trust-remote-code \
  --max-model-len 32768 \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1000 8x vLLM 0.21

```bash
export VLLM_ROCM_USE_AITER=0
export VLLM_ROCM_USE_AITER_MOE=0

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  -tp 8 \
  --trust-remote-code \
  --max-model-len 32768 \
  --max-num-batched-tokens 10240 \
  --gpu-memory-utilization 0.95 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1100 4x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_ROCM_USE_AITER=1
export VLLM_ROCM_USE_AITER_MOE=1

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1000 8x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_ROCM_USE_AITER=1
export VLLM_ROCM_USE_AITER_MOE=1

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  -tp 8 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --gpu-memory-utilization 0.95
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1100 4x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1
vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM \
  --moe-backend aiter
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1000 8x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1
vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  -tp 8 \
  --trust-remote-code \
  --max-model-len 20480 \
  --max-num-batched-tokens 10240 \
  --gpu-memory-utilization 0.95 \
  --attention-backend FLASH_ATTN_CUSTOM \
  --moe-backend aiter
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1100 4x vLLM 0.15

```bash

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  --dtype float16 \
  --trust-remote-code \
  -tp 4 \
  --disable-cascade-attn 
```

### Qwen3-235B-A22B-Instruct-2507 IFB BW1000 8x vLLM 0.15

```bash

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  --dtype float16 \
  --trust-remote-code \
  -tp 8 \
  --gpu-memory-utilization 0.95 \
  --max-model-len 40960 \
  --disable-cascade-attn
```

### Qwen3-235B-A22B-Instruct-2507 IFB K100_AI 8x vLLM 0.15

```bash
export ALLREDUCE_STREAM_WITH_COMPUTE=1

vllm serve Qwen/Qwen3-235B-A22B-Instruct-2507 \
  --dtype float16 \
  --trust-remote-code \
  -tp 8 \
  --gpu-memory-utilization 0.95 \
  --max-model-len 40960 \
  --disable-cascade-attn
```

### Qwen3-Next-80B-A3B-Instruct IFB BW1100 4x vLLM 0.21

```bash
vllm serve Qwen/Qwen3-Next-80B-A3B-Instruct \
  --dtype float16 \
  --tensor-parallel-size 4 \
  --gpu-memory-utilization 0.9 \
  --max-num-seqs 128 \
  --trust-remote-code \
  --moe-backend triton \
  --compilation-config \
    '{"mode":"NONE","cudagraph_mode":"FULL_DECODE_ONLY"}'
```

### Qwen3-Next-80B-A3B-Instruct IFB BW1000 4x vLLM 0.21

```bash
vllm serve Qwen/Qwen3-Next-80B-A3B-Instruct \
  --dtype float16 \
  --tensor-parallel-size 4 \
  --gpu-memory-utilization 0.9 \
  --max-num-seqs 128 \
  --trust-remote-code \
  --moe-backend triton \
  --compilation-config \
    '{"mode":"NONE","cudagraph_mode":"FULL_DECODE_ONLY"}'
```

### Qwen3-Coder-480B-A35B-Instruct-FP8-Dynamic IFB BW1100 8x vLLM 0.21

```bash
vllm serve /models/Qwen3-Coder-480B-A35B-Instruct-FP8-Dynamic \
  --trust-remote-code \
  --dtype bfloat16 \
  --max-model-len 262144 \
  -tp 8 \
  --gpu-memory-utilization 0.9 \
  --max-num-seqs 128 \
  --block-size 64 \
  --max-num-batched-tokens 16384 \
  --no-enable-prefix-caching \
  --enable-chunked-prefill \
  --kv-cache-dtype fp8_e4m3 \
  --moe-backend triton \
  --compilation-config '{"pass_config": {"fuse_act_quant": false}}'
```

### Qwen3-235B-A22B IFB BW1100 4x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_ROCM_USE_AITER=1
export VLLM_ROCM_USE_AITER_MOE=1

vllm serve Qwen/Qwen3-235B-A22B \
  --host 0.0.0.0 \
  -tp 4 \
  --gpu-memory-utilization 0.9 \
  --trust-remote-code \
  --max-model-len 32768
```

### Qwen3-235B-A22B IFB BW1000 8x vLLM 0.18

```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1
export VLLM_ROCM_USE_AITER=1
export VLLM_ROCM_USE_AITER_MOE=1

vllm serve Qwen/Qwen3-235B-A22B \
  --host 0.0.0.0 \
  -tp 8 \
  --gpu-memory-utilization 0.9 \
  --trust-remote-code \
  --max-model-len 32768
```

### Qwen3-235B-A22B IFB K100_AI 8x vLLM 0.18

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve Qwen/Qwen3-235B-A22B \
  --host 0.0.0.0 \
  -tp 8 \
  --gpu-memory-utilization 0.95 \
  --trust-remote-code \
  --max-model-len 32768
```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB BW1100 2x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-235B-A22B-Channel-INT8-w8a8  \
  -tp  2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --max-model-len 40960 \
  --gpu-memory-utilization 0.95 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM

```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB BW1000 4x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-235B-A22B-Channel-INT8-w8a8 \
  -tp  4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --max-model-len 40960 \
  --gpu-memory-utilization 0.95 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB K100_AI 4x vLLM 0.21

```bash

export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0
export VLLM_ROCM_USE_AITER=0
vllm serve hygon/Qwen3-235B-A22B-Channel-INT8-w8a8 \
  -tp 4 \
  --gpu-memory-utilization 0.9 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --attention-backend TRITON_ATTN
```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB BW1100 2x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-235B-A22B-Channel-INT8-w8a8  \
  -tp  2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --max-model-len 40960 \
  --gpu-memory-utilization 0.95
```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB BW1000 4x vLLM 0.18
```bash
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-235B-A22B-Channel-INT8-w8a8 \
  -tp  4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --max-model-len 40960 \
  --gpu-memory-utilization 0.95
```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB K100_AI 4x vLLM 0.18

```bash
export VLLM_HCU_USE_CUSTOM_QUANTIZATION_GEMM=0
export VLLM_HCU_USE_CUSTOM_OPS=0

vllm serve hygon/Qwen3-235B-A22B-Channel-INT8-w8a8 \
  -tp 4 \
  --gpu-memory-utilization 0.9 \
  --trust-remote-code \
  --max-num-batched-tokens 10240
```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB BW1100 2x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-235B-A22B-Channel-INT8-w8a8  \
  -tp  2 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --max-model-len 40960 \
  --gpu-memory-utilization 0.95 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM

```

### Qwen3-235B-A22B-Channel-INT8-w8a8 IFB BW1000 4x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-235B-A22B-Channel-INT8-w8a8 \
  -tp  4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --max-model-len 40960 \
  --gpu-memory-utilization 0.95 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-FP8-Channelwise IFB BW1100 4x vLLM 0.21

```bash

vllm serve Qwen/Qwen3-235B-A22B-FP8-Channelwise \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-FP8-Channelwise IFB BW1100 4x vLLM 0.18
```bash
export VLLM_HCU_USE_PD_SPLIT=1
export VLLM_HCU_USE_CUSTOM_FLASH_ATTN=1

vllm serve Qwen/Qwen3-235B-A22B-FP8-Channelwise \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 
```

### Qwen3-235B-A22B-FP8-Channelwise IFB BW1100 4x vLLM 0.18-hotfix

```bash
export VLLM_HCU_USE_PD_SPLIT=1

vllm serve Qwen/Qwen3-235B-A22B-FP8-Channelwise \
  -tp 4 \
  --trust-remote-code \
  --max-num-batched-tokens 10240 \
  --kv-cache-dtype fp8_e4m3 \
  --attention-backend FLASH_ATTN_CUSTOM
```

### Qwen3-235B-A22B-FP8-Channelwise IFB BW1100 4x vLLM 0.15
```bash
export VLLM_USE_LIGHTOP=1
export LMSLIM_USE_LIGHTOP=1
export VLLM_USE_LIGHTOP_MOE_ALIGN=1
export VLLM_USE_LIGHTOP_FILL_MOE_ALIGN=1
export VLLM_USE_OPT_RESHAPE_AND_CACHE=1
export VLLM_USE_GLOBAL_CACHE13=1
export VLLM_FUSED_MOE_CHUNK_SIZE=16384
export VLLM_USE_PIECEWISE=1
export VLLM_USE_LIGHTOP_FUSED_TOPP_TOPK=1

vllm serve Qwen/Qwen3-235B-A22B-FP8-Channelwise \
  -tp 4 \
  --trust-remote-code \
  --dtype bfloat16 \
  -q slimquant_marlin \
  --disable-cascade-attn \
  -cc '{"pass_config": {"fuse_act_quant": false}, "custom_ops": ["all"]}'
```




## 环境变量

| 环境变量 | 值 | 对总吞吐 | 对 TPOT | 说明 |
|---------|---|---------|---------|------|
| `VLLM_USE_PD_SPLIT` | `1`（默认） | 友好 | 不友好 | PD 分离调度，prefill 独占 step，decode 被饿死 |
| `VLLM_USE_PD_SPLIT` | `0` | 不友好 | 友好 | 混合调度，decode 不被 prefill 阻塞 |
| `VLLM_USE_PIECEWISE` | `1` | 友好 | 不友好 | 分段 CUDA Graph，适配动态 batch，吞吐稳定 |
| `VLLM_USE_PIECEWISE` | `0`（默认） | 不友好 | 友好 | 整块 CUDA Graph，执行开销小，单步延迟低 |

## API 调用

### 普通对话

```python
from openai import OpenAI

client = OpenAI(base_url="http://localhost:8000/v1", api_key="not-needed")

response = client.chat.completions.create(
    model="Qwen/Qwen3-8B",
    messages=[{"role": "user", "content": "解释量子计算的基本原理"}],
    max_tokens=1024,
)
print(response.choices[0].message.content)
```

```bash
curl http://localhost:8000/v1/chat/completions \
  -H "Content-Type: application/json" \
  -d '{
  "model": "Qwen/Qwen3-8B",
  "messages": [
    {"role": "user", "content": "解释量子计算的基本原理"}
  ],
  "max_tokens": 1024
  }'
```

### 思考模式（Thinking Mode）

```python
response = client.chat.completions.create(
    model="Qwen/Qwen3-8B",
    messages=[
        {"role": "user", "content": "解方程: 3x^2 - 7x + 2 = 0"},
    ],
    max_tokens=4096,
    extra_body={"chat_template_kwargs": {"enable_thinking": True}},
)

# 思考过程在 reasoning_content 中
message = response.choices[0].message
if hasattr(message, "reasoning_content"):
    print("=== 思考过程 ===")
    print(message.reasoning_content)
print("=== 最终回答 ===")
print(message.content)
```

### 工具调用（Function Calling）

```python
tools = [{
    "type": "function",
    "function": {
        "name": "get_weather",
        "description": "获取指定城市的天气信息",
        "parameters": {
            "type": "object",
            "properties": {
                "city": {"type": "string", "description": "城市名称"},
            },
            "required": ["city"],
        },
    },
}]

response = client.chat.completions.create(
    model="Qwen/Qwen3-8B",
    messages=[{"role": "user", "content": "北京今天天气怎么样？"}],
    tools=tools,
    tool_choice="auto",
)
print(response.choices[0].message.tool_calls)
```

