# precision_estimation/examples/relu_precision_pipeline.py
import time
import json
import torch
import torch.multiprocessing as mp

from core.config.precision_strategy import get_precision_strategy
from core.generator.relu_generator import ReLUInputGenerator
from core.oracle.relu_oracle_mc import DataAwareMCReLUOracle
from core.detector.relu_error_detector import ReLUErrorDetector
from core.analyzer.relu_error_analyzer import ReLUErrorAnalyzer


def pretty_float(x):
    try:
        return float(x)
    except Exception:
        return x


def main():
    num_batches = 2000

    # 1) Select mixed precision strategy
    strategy = get_precision_strategy("FP16_input_FP32_weight_FP32_compute_accum")
    print("Using strategy:", strategy)

    # 2) Construct input generator (stay on CPU as you prefer)
    gen = ReLUInputGenerator(
        input_shape=(1, 256, 32, 32),
        distribution="boundary",
        device="cpu",   # 生成仍在 CPU
        seed=42,
    )

    # 3) Construct Oracle (no device forcing; it follows x.device)
    devices = list(range(torch.cuda.device_count())) if torch.cuda.is_available() else []
    oracle = DataAwareMCReLUOracle(
        strategy=strategy,
        num_mc_samples=512,
        quantile=0.999,
        safety_factor=1.10,
        seeded=True,
        devices=devices,
        enable_noise_input=False,  # ReLU 默认关闭输入计算噪声
        enable_noise_output=False,  # 如需最紧上界可改 False
        # 若你的 Oracle 没有 component_samples 参数，可删掉下一行
        component_samples=32,
    )
    analyzer = ReLUErrorAnalyzer()

    # （可选）让 cuDNN 做算法选择，固定形状时更快
    if torch.cuda.is_available():
        torch.backends.cudnn.benchmark = True

    for batch_id in range(1, num_batches + 1):
        print(f"\n===== Batch {batch_id}/{num_batches} =====")

        # Generate input data on CPU
        x, meta = gen.generate()

        # --- 最小改动：如可用，把张量搬到 GPU，其它不变 ---
        if torch.cuda.is_available():
            x = x.to("cuda", non_blocking=True)
        # ---------------------------------------------------

        # 4) Construct detector and run detection
        detector = ReLUErrorDetector(strategy, oracle)

        t0 = time.time()
        exceeded, actual_err, bound, oracle_result = detector.detect(x)
        dt = time.time() - t0

        print(f"Detection time: {dt:.3f}s")
        print(f"Maximum actual error: {actual_err:.6e}")
        print(f"Oracle predicted error bound: ±{bound:.6e}")
        print(f"Exceeded predicted bound: {'Yes' if bool(exceeded) else 'No'}")

        # 5) Call Analyzer
        print("Performing interpretability analysis (element-level)...")
        report = analyzer.analyze(
            oracle_result,
            x=x,
            strategy=strategy,
            top_k=10,
        )

        # 6) Print high-level summary
        print("\n-- Error Decomposition (High-level) --")
        for k, v in report.get("component_estimates", {}).items():
            print(f"  {k}: {pretty_float(v):.3e}")
        print("-- Ratios --")
        for k, v in report.get("component_ratios", {}).items():
            print(f"  {k}: {v:.3f}")
        print("Primary error source:", report.get("primary_source") or report.get("primary_source_refined"))

        # ReLU behavior statistics
        if "relu_behavior_stats" in report:
            print("-- ReLU Behavior Statistics --")
            for behavior, count in report["relu_behavior_stats"].items():
                print(f"  {behavior}: {count}")

        print("Suggestion:", report.get("suggestion"))

        # 7) Print top-k critical elements
        top_elements = report.get("top_elements", [])
        if top_elements:
            print(f"\n-- Top {len(top_elements)} Critical Element Analysis --")
            for idx, elem in enumerate(top_elements):
                print(f"\n[{idx+1}] Coordinate: {elem['coord']}")
                print(f"    element_error = {elem['element_error']:.6e}")
                print(f"    x_original = {elem['x_original']:.6e}")
                print(f"    x_quantized = {elem['x_quantized']:.6e}")
                print(f"    y_ref = {elem['y_ref']:.6e}")
                print(f"    y_mixed = {elem['y_mixed']:.6e}")
                print(f"    storage_error = {elem['storage_error']:.6e}")
                print(f"    demote_error = {elem['demote_error']:.6e}")
                print(f"    relu_behavior = {elem['relu_behavior']}")

        # 8) Save JSON
        out_json = {
            "detector": {
                "detected_exceeded": bool(exceeded),
                "actual_err": actual_err,
                "predicted_bound": bound,
                "elapsed_sec": dt,
            },
            "analyzer_report": {
                "component_estimates": report.get("component_estimates", {}),
                "component_ratios": report.get("component_ratios", {}),
                "primary_source": report.get("primary_source_refined", report.get("primary_source")),
                "suggestion": report.get("suggestion", ""),
                "relu_behavior_stats": report.get("relu_behavior_stats", {}),
                "top_elements_summary": [
                    {
                        "coord": elem["coord"],
                        "element_error": elem["element_error"],
                        "x_original": elem["x_original"],
                        "y_ref": elem["y_ref"],
                        "y_mixed": elem["y_mixed"],
                        "relu_behavior": elem["relu_behavior"],
                        "storage_error": elem["storage_error"],
                        "demote_error": elem["demote_error"],
                    }
                    for elem in top_elements
                ],
            },
        }

        json_filename = f"evaluation/experiment_1/default_relu_analysis_batch{batch_id}.json"
        with open(json_filename, "w") as f:
            json.dump(out_json, f, indent=2)
        print(f"\nAnalysis results saved to {json_filename}")

    print("\nAll batches completed")


if __name__ == "__main__":
    try:
        mp.set_start_method("spawn", force=True)
    except RuntimeError:
        pass
    main()
