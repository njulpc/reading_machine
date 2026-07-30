# 深度技术分析：TileFuse: A Fused Mixed-Precision Kernel Library for Efficient Quantized LLM Inference on AMD NPUs

> **arXiv ID**: [2606.11357](https://arxiv.org/abs/2606.11357)  |  **提交日期**: 2026-06-09  |  **分类**: cs.DC, cs.AI, cs.AR, cs.PF  |  **作者**: Wesley Pang, Gregory Hyegang Jun, Feiyang Liu 等
> **备注**: 13 pages excluding reference, 11 figures

> ⚠️ 本文档基于 arXiv 摘要与元数据撰写，未逐字核对全文；所有数字均引自摘要原文。


---

## 一、核心速览

**研究主题**：量化硬件部署（硬件部署、量化）—— 面向大语言模型（LLM）的模型压缩

**一句话总结**：本文研究了面向大语言模型（LLM）的量化硬件部署方法/研究「TileFuse」，关键结果包括：121.6%。（基于摘要）

**技术标签**: hardware-deployment / quantization


---

## 二、研究背景与动机 (Background & Motivation)

量化算法的最终价值取决于硬件落地：FPGA、NPU、消费级 GPU 与嵌入式平台上的量化推理涉及整数-only 数据通路、混合精度 kernel、DSP 打包与内存层次优化等系统问题。算法-硬件协同设计（如面向特定数据通路的量化格式与融合算子）是实现真实加速比与能效收益的关键。

### 2.1 本文切入点

摘要开篇指出：

> With the growing demand for on-device LLM inference, edge SoCs increasingly integrate NPUs to improve performance and energy efficiency under tight power and thermal budgets.


并进一步阐述了问题设定：

> However, practical LLM deployment on current client NPUs remains difficult: widely used quantization formats such as AWQ do not map cleanly onto many existing NPU software stacks, which are often proprietary and expose limited low-level control.


从问题陈述看，作者针对的是大语言模型（LLM）在量化硬件部署场景下的具体瓶颈，属于 quant-hardware 技术路线。


---

## 三、核心方法与创新点 (Methodology & Innovations)

根据摘要可识别的核心方法组件：

- **方法要点 1**：However, practical LLM deployment on current client NPUs remains difficult: widely used quantization formats such as AWQ do not map cleanly onto many existing NPU software stacks, which are often proprietary and expose limited low-level control.
- **方法要点 2**：In this work, we present TileFuse, a close-to-metal mixed-precision kernel library for AMD XDNA2 NPUs that targets GEMM/GEMV-based operators in quantized LLM inference.
- **方法要点 3**：TileFuse brings practical low-bit formats such as AWQ-style W4A16 and W8A16 directly onto XDNA2, rather than forcing the model to be reshaped around an NPU-specific quantization scheme.
- **方法要点 4**：TileFuse co-designs weight layout, metadata placement, mixed-precision microkernels, and array-level dataflow.
- **方法要点 5**：Specifically, it fuses unpacking, dequantization, and GEMM/GEMV execution into a single kernel flow, introduces an interleaved pre-tiling layout that supports GEMM dimensions up to 32K, and redesigns GEMV dataflow to utilize the full 4x8 AIE array.

**方法学点评**：硬件导向量化工作的评估应关注：报告的是峰值算力利用率还是端到端加速、是否包含量化/反量化开销、以及与现有推理框架（TensorRT-LLM、vLLM 等）的对比。


---

## 四、实验设计与结果 (Experiments & Results)

摘要中报告的关键定量结果（原文句子摘录）：

- In this work, we present TileFuse, a close-to-metal mixed-precision kernel library for AMD XDNA2 NPUs that targets GEMM/GEMV-based operators in quantized LLM inference.
- TileFuse brings practical low-bit formats such as AWQ-style W4A16 and W8A16 directly onto XDNA2, rather than forcing the model to be reshaped around an NPU-specific quantization scheme.
- Specifically, it fuses unpacking, dequantization, and GEMM/GEMV execution into a single kernel flow, introduces an interleaved pre-tiling layout that supports GEMM dimensions up to 32K, and redesigns GEMV dataflow to utilize the full 4x8 AIE array.
- Across kernel-level evaluations, TileFuse improves performance by up to 121.6% for GEMM and 281% for GEMV over full-precision baselines, while delivering more than 2x performance and energy-efficiency gains over strong iGPU baselines on GEMM.
- In end-to-end LLM experiments on Ryzen AI laptops, TileFuse achieves up to 2.0x lower prefilling latency with more than 64.6% lower energy consumption.
- Together, these results show that XDNA2 is a practical target for AWQ-style edge LLM inference and that native NPU support for off-the-shelf quantization can make NPUs substantially more usable in real client deployments.

**结果解读**：以上数字均直接引自摘要原文。评估该类工作时建议对照同月同方向工作（见月度报告横向比较表）判断其增益幅度。


---

## 五、局限性与未来展望 (Limitations & Future Work)

硬件类工作的结论与特定平台绑定，跨平台可迁移性有限；报告的加速比也可能依赖特定的 batch/序列配置。

此外，本文档基于摘要与 arXiv 元数据撰写，未获取全文，方法细节、实验设置与更完整的局限讨论以原文为准。


**未来展望**：未来方向：编译器级量化 lowering、跨平台统一中间表示。


---

## 六、学术启发 (Takeaways for My Research)

- 算法-硬件协同设计的收益往往大于纯算法改进：为数据通路定制量化格式是实用捷径
- 端到端评测（含量化/反量化开销）是硬件论文的诚信底线
- 结合本文：可将「TileFuse」的思路迁移到 Qwen3-0.6B 等小模型上验证其在小参数量 regime 下的有效性（见 scripts/quantization 下对应 demo，若已复现）。
