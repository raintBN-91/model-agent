#!/usr/bin/env python3
"""CPU vs NPU 精度对比脚本（通用，支持所有 Twins 模型）"""
import argparse
import gc
import os
import time

import torch
import torch_npu
import timm
from timm.data import resolve_model_data_config, create_transform
import numpy as np
from PIL import Image
from io import BytesIO

from ms_loader import load_timm_model


def parse_args():
    parser = argparse.ArgumentParser(description="CPU vs NPU 精度对比")
    parser.add_argument("--model-name", type=str, required=True,
                        help="模型名称")
    parser.add_argument("--image-url", type=str, default=None,
                        help="测试图片 URL")
    parser.add_argument("--image-path", type=str, default=None,
                        help="本地测试图片路径")
    return parser.parse_args()


def load_image(url=None, path=None):
    img = None
    if path and os.path.exists(path):
        img = Image.open(path).convert("RGB")
    elif url:
        try:
            resp = requests.get(url, timeout=15)
            img = Image.open(BytesIO(resp.content)).convert("RGB")
        except Exception:
            pass
    if img is None:
        import numpy as np
        arr = np.zeros((224, 224, 3), dtype=np.uint8)
        for y in range(224):
            for x in range(224):
                arr[y, x, 0] = int(255 * y / 223)
                arr[y, x, 1] = int(255 * x / 223)
                arr[y, x, 2] = int(128 + 127 * (x+y) / 446)
        img = Image.fromarray(arr, "RGB")
    return img


@torch.no_grad()
def main():
    args = parse_args()
    model_name = args.model_name
    print(f"{'='*60}")
    print(f"  模型: {model_name}")
    print(f"  CPU vs NPU 精度对比")
    print(f"{'='*60}")

    # 加载模型（CPU）
    print("\n[INFO] 加载模型 (CPU)...")
    model_cpu = load_timm_model(model_name)

    # 加载模型（NPU）
    print("[INFO] 加载模型 (NPU)...")
    model_npu = load_timm_model(model_name)
    model_npu = model_npu.npu()

    # 数据预处理
    data_config = resolve_model_data_config(model_cpu)
    transforms = create_transform(**data_config)

    # 加载图片
    img = load_image(args.image_url, args.image_path)
    input_tensor = transforms(img).unsqueeze(0)

    # CPU 推理
    print("\n[INFO] CPU 推理...")
    t_cpu0 = time.time()
    out_cpu = model_cpu(input_tensor)
    t_cpu = time.time() - t_cpu0
    probs_cpu = torch.nn.functional.softmax(out_cpu, dim=1)

    # NPU 推理
    print("[INFO] NPU 推理...")
    input_npu = input_tensor.npu()
    t_npu0 = time.time()
    out_npu = model_npu(input_npu)
    torch.npu.synchronize()
    t_npu = time.time() - t_npu0
    out_npu = out_npu.cpu()
    probs_npu = torch.nn.functional.softmax(out_npu, dim=1)

    # 精度对比
    print("\n" + "="*60)
    print("  精度对比结果")
    print("="*60)

    # 1. Logits 差异
    logits_diff = torch.abs(out_cpu - out_npu)
    logits_rel_diff = logits_diff / (torch.abs(out_cpu) + 1e-8)

    max_abs_err = logits_diff.max().item()
    mean_abs_err = logits_diff.mean().item()
    max_rel_err = logits_rel_diff.max().item() * 100
    mean_rel_err = logits_rel_diff.mean().item() * 100

    print(f"\n  Logits 差异:")
    print(f"    Max Absolute Error: {max_abs_err:.6f}")
    print(f"    Mean Absolute Error: {mean_abs_err:.8f}")
    print(f"    Max Relative Error: {max_rel_err:.4f}%")
    print(f"    Mean Relative Error: {mean_rel_err:.4f}%")

    # 2. 概率差异
    prob_diff = torch.abs(probs_cpu - probs_npu)
    max_prob_diff = prob_diff.max().item()
    mean_prob_diff = prob_diff.mean().item()

    print(f"\n  概率差异:")
    print(f"    Max Probability Difference: {max_prob_diff:.6f}")
    print(f"    Mean Probability Difference: {mean_prob_diff:.8f}")

    # 3. Top-1 / Top-5 一致性
    top1_cpu = out_cpu.argmax(dim=1).item()
    top1_npu = out_npu.argmax(dim=1).item()
    _, top5_cpu = torch.topk(out_cpu, 5, dim=1)
    _, top5_npu = torch.topk(out_npu, 5, dim=1)
    top5_cpu_set = set(top5_cpu[0].tolist())
    top5_npu_set = set(top5_npu[0].tolist())

    print(f"\n  分类一致性:")
    print(f"    CPU Top-1 class: {top1_cpu}")
    print(f"    NPU Top-1 class: {top1_npu}")
    print(f"    Top-1 match: {'YES' if top1_cpu == top1_npu else 'NO'}")
    print(f"    Top-5 overlap: {len(top5_cpu_set & top5_npu_set)}/5")

    # 4. Cosine similarity
    cos_sim = torch.nn.functional.cosine_similarity(out_cpu, out_npu, dim=1).item()

    print(f"\n  Cosine Similarity: {cos_sim:.8f}")

    # 5. 性能对比
    print(f"\n  推理耗时:")
    print(f"    CPU: {t_cpu*1000:.2f}ms")
    print(f"    NPU: {t_npu*1000:.2f}ms")
    print(f"    Speedup: {t_cpu/t_npu:.2f}x")

    # 结论
    # 对于分类模型，使用概率差异和余弦相似度作为精度指标
    # 相对误差在 logits 接近 0 时会被不合理放大
    passed = max_prob_diff < 0.01  # 概率差异 < 1%
    print(f"\n{'='*60}")
    print(f"  结论: {'通过' if passed else '失败'}")
    if passed:
        print(f"  NPU 与 CPU 推理结果误差 < 1%（基于概率差异和分类一致性）")
    else:
        print(f"  最大概率差异 = {max_prob_diff:.6f}，超过 1% 阈值")
    print(f"{'='*60}")

    # 保存结果
    model_tag = model_name.replace(".", "_")
    os.makedirs(f"{model_tag}_compare", exist_ok=True)
    np.save(f"{model_tag}_compare/cpu_logits.npy", out_cpu.numpy())
    np.save(f"{model_tag}_compare/npu_logits.npy", out_npu.numpy())

    # 输出总结
    print(f"\n\n【精度对比摘要】")
    print(f"| 指标 | 数值 |")
    print(f"|---|---:|")
    print(f"| Max Absolute Error | {max_abs_err:.6f} |")
    print(f"| Mean Absolute Error | {mean_abs_err:.8f} |")
    print(f"| Max Relative Error | {max_rel_err:.4f}% |")
    print(f"| Mean Relative Error | {mean_rel_err:.4f}% |")
    print(f"| Max Prob Difference | {max_prob_diff:.6f} |")
    print(f"| Mean Prob Difference | {mean_prob_diff:.8f} |")
    print(f"| Cosine Similarity | {cos_sim:.8f} |")
    print(f"| Top-1 Match | {'Yes' if top1_cpu == top1_npu else 'No'} |")
    print(f"| Top-5 Overlap | {len(top5_cpu_set & top5_npu_set)}/5 |")
    print(f"| CPU Time | {t_cpu*1000:.2f}ms |")
    print(f"| NPU Time | {t_npu*1000:.2f}ms |")
    print(f"| Speedup | {t_cpu/t_npu:.2f}x |")

    # 释放资源
    del model_cpu, model_npu, input_tensor, input_npu
    gc.collect()
    torch.npu.empty_cache()


if __name__ == "__main__":
    main()
