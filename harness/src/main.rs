#![allow(clippy::print_literal)]

use clap::Parser;
use serde::{Deserialize, Serialize};
use std::path::{Path, PathBuf};
use std::process::Command;

/// Result produced by each framework benchmark runner.
/// Every runner must print exactly one JSON object matching this schema to stdout.
/// Extra framework-specific fields (e.g. torch_version) are preserved in `extra`.
#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct BenchResult {
    pub framework: String,
    pub model: String,
    pub device: String,
    pub gpu_name: String,
    pub timings: Timings,
    pub outputs: Outputs,
    /// Framework-specific extra fields (torch_version, driver_name, etc.).
    #[serde(flatten)]
    pub extra: serde_json::Map<String, serde_json::Value>,
}

#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct Timings {
    /// Time to compile/optimize the model (seconds).
    pub compile_s: f64,
    /// Inference (full forward pass) time (milliseconds).
    pub inference_ms: f64,
    /// Single-token / minimal-input latency (milliseconds).
    #[serde(default)]
    pub latency_ms: f64,
    /// Training backward pass time (milliseconds).
    pub training_ms: f64,
}

#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct Outputs {
    /// SHA-256 hash of the full logits tensor (flattened, f32 little-endian bytes).
    pub logits_hash: String,
    /// First 16 logit values for quick human inspection.
    pub logits_sample: Vec<f64>,
    /// Scalar loss value from the fake training step.
    pub loss: f64,
}

/// Outcome for a framework: either a result or a failure reason.
#[derive(Debug, Clone, Serialize, Deserialize)]
#[serde(tag = "status")]
pub enum FrameworkOutcome {
    #[serde(rename = "ok")]
    Ok(BenchResult),
    #[serde(rename = "error")]
    Error {
        framework: String,
        model: String,
        error: String,
    },
    #[serde(rename = "skipped")]
    Skipped {
        framework: String,
        model: String,
        reason: String,
    },
}

#[derive(Parser)]
#[command(name = "inferena", about = "Inference Arena")]
struct Cli {
    /// Which frameworks to benchmark (omit for all).
    #[arg(short, long, value_delimiter = ',')]
    frameworks: Option<Vec<String>>,

    /// Model to benchmark.
    #[arg(short, long, default_value = "SmolLM2-135M")]
    model: String,

    /// Path to the project root (auto-detected if omitted).
    #[arg(long)]
    root: Option<PathBuf>,

    /// Output results as JSON array instead of a human-readable table.
    #[arg(long)]
    json: bool,

    /// Dry-run: validate framework+model support without running benchmarks.
    #[arg(long)]
    dry_run: bool,
}

fn all_frameworks() -> Vec<&'static str> {
    let mut v = vec![
        "pytorch",
        "candle",
        "burn",
        "inferi",
        "luminal",
        "meganeura",
        "ggml",
        "onnxruntime",
        "max",
        "jax",
    ];
    if cfg!(target_os = "macos") {
        v.insert(1, "mlx"); // after pytorch
    }
    v
}

/// Framework metadata: (display_name, repo_url).
fn framework_meta(name: &str) -> (&'static str, &'static str) {
    match name {
        "pytorch" => ("PyTorch", "https://github.com/pytorch/pytorch"),
        "mlx" => ("MLX", "https://github.com/ml-explore/mlx"),
        "candle" => ("Candle", "https://github.com/huggingface/candle"),
        "burn" => ("Burn", "https://github.com/tracel-ai/burn"),
        "luminal" => ("Luminal", "https://github.com/luminal-ai/luminal"),
        "meganeura" => ("Meganeura", "https://github.com/kvark/meganeura"),
        "inferi" => ("Inferi", "https://github.com/dimforge/inferi"),
        "ggml" => ("GGML", "https://github.com/ggerganov/ggml"),
        "onnxruntime" => ("ONNX Runtime", "https://github.com/microsoft/onnxruntime"),
        "max" => ("MAX", "https://github.com/modular/modular"),
        "jax" => ("JAX", "https://github.com/jax-ml/jax"),
        _ => ("unknown", ""),
    }
}

/// Format framework name as a markdown link with backend.
/// Revision comes from the runner's JSON output ("framework_rev" field),
/// which each run.sh extracts from Cargo.lock.
fn framework_md_link(name: &str, extra: &serde_json::Map<String, serde_json::Value>) -> String {
    let (display, url) = framework_meta(name);
    if url.is_empty() {
        return display.to_string();
    }

    let rev = extra
        .get("framework_rev")
        .and_then(|v| v.as_str())
        .unwrap_or("");

    let link = if name == "pytorch" {
        let ver = extra
            .get("torch_version")
            .and_then(|v| v.as_str())
            .unwrap_or("");
        if !ver.is_empty() {
            let base_ver = ver.split('+').next().unwrap_or(ver);
            format!("[{display} {ver}]({url}/releases/tag/v{base_ver})")
        } else {
            format!("[{display}]({url})")
        }
    } else if rev.is_empty() {
        format!("[{display}]({url})")
    } else {
        format!("[{display}]({url}/tree/{rev})")
    };

    // Append backend in parens if available.
    let backend = extra.get("backend").and_then(|v| v.as_str()).unwrap_or("");
    if !backend.is_empty() {
        format!("{link} ({backend})")
    } else {
        // For Rust frameworks, infer backend from framework name.
        let inferred = match name {
            "candle" => "CPU",
            "burn" => "wgpu",
            "luminal" => "CPU",
            "meganeura" => {
                if cfg!(target_os = "macos") {
                    "Metal"
                } else {
                    "Vulkan"
                }
            }
            "inferi" => {
                if cfg!(target_os = "macos") {
                    "Metal"
                } else {
                    "Vulkan"
                }
            }
            "mlx" => "MLX",
            "ggml" => "CPU",
            "onnxruntime" => "CPU",
            "max" => "CPU",
            "jax" => "CPU",
            _ => "",
        };
        if inferred.is_empty() {
            link
        } else {
            format!("{link} ({inferred})")
        }
    }
}

fn project_root(cli_root: Option<&Path>) -> PathBuf {
    if let Some(r) = cli_root {
        // Don't canonicalize — on Windows, std::fs::canonicalize returns paths
        // with the `\\?\` extended-length prefix, which git-bash's bash cannot
        // open. Callers already pass an absolute path.
        return r.to_path_buf();
    }
    let exe = std::env::current_exe().unwrap_or_else(|_| PathBuf::from("."));
    let mut dir = exe.parent().unwrap_or(Path::new(".")).to_path_buf();
    for _ in 0..5 {
        if dir.join("Cargo.toml").exists() && dir.join("frameworks").exists() {
            return dir;
        }
        if !dir.pop() {
            break;
        }
    }
    std::env::current_dir().unwrap_or_else(|_| PathBuf::from("."))
}

fn run_framework(root: &Path, framework: &str, model: &str, dry_run: bool) -> FrameworkOutcome {
    let fw_dir = root.join("frameworks").join(framework);
    let run_script = fw_dir.join("run.sh");

    if !run_script.exists() {
        return FrameworkOutcome::Skipped {
            framework: framework.to_string(),
            model: model.to_string(),
            reason: format!("run.sh not found at {}", run_script.display()),
        };
    }

    if dry_run {
        eprintln!("[{framework}] dry-run for {model} ...");
    } else {
        eprintln!("[{framework}] running benchmark for {model} ...");
    }

    // Always use bash (Git Bash on Windows).
    // Inherits environment so WGPU_BACKEND, HSA_OVERRIDE_GFX_VERSION, etc. propagate.
    let mut cmd = Command::new("bash");
    cmd.arg(&run_script).arg(model).current_dir(&fw_dir);
    if dry_run {
        cmd.env("INFERENA_DRY_RUN", "1");
    }
    let output = cmd.output();

    let output = match output {
        Ok(o) => o,
        Err(e) => {
            return FrameworkOutcome::Error {
                framework: framework.to_string(),
                model: model.to_string(),
                error: format!("failed to execute run.sh: {e}"),
            };
        }
    };

    if !output.status.success() {
        let stderr = String::from_utf8_lossy(&output.stderr);
        let stdout = String::from_utf8_lossy(&output.stdout);
        let combined = format!("{stderr}\n{stdout}");
        // Truncate long error output for readability.
        let stderr_short: String = stderr.lines().take(20).collect::<Vec<_>>().join("\n");

        // "Unknown model" / "unsupported" → skip, not error.
        let lower = combined.to_lowercase();
        if lower.contains("unknown model") || lower.contains("unsupported") {
            return FrameworkOutcome::Skipped {
                framework: framework.to_string(),
                model: model.to_string(),
                reason: format!("model not supported by {framework}"),
            };
        }

        return FrameworkOutcome::Error {
            framework: framework.to_string(),
            model: model.to_string(),
            error: format!("{}: {}", output.status, stderr_short),
        };
    }

    let stdout = String::from_utf8_lossy(&output.stdout);
    let json_str = match stdout
        .lines()
        .rev()
        .find(|l| l.trim_start().starts_with('{'))
    {
        Some(s) => s,
        None => {
            // In dry-run, no JSON output is fine — the framework validated OK.
            if dry_run {
                return FrameworkOutcome::Skipped {
                    framework: framework.to_string(),
                    model: model.to_string(),
                    reason: "dry-run OK (no benchmark data)".to_string(),
                };
            }
            return FrameworkOutcome::Error {
                framework: framework.to_string(),
                model: model.to_string(),
                error: "no JSON found in stdout".to_string(),
            };
        }
    };

    match serde_json::from_str::<BenchResult>(json_str) {
        Ok(r) => FrameworkOutcome::Ok(r),
        Err(e) => FrameworkOutcome::Error {
            framework: framework.to_string(),
            model: model.to_string(),
            error: format!("JSON parse error: {e}"),
        },
    }
}

/// Save each framework's result as a separate JSON file in results/.
fn save_results(root: &Path, model: &str, outcomes: &[FrameworkOutcome]) {
    let results_dir = root.join("results");
    std::fs::create_dir_all(&results_dir).ok();

    for outcome in outcomes {
        let (fw, content) = match outcome {
            FrameworkOutcome::Ok(r) => {
                (&r.framework, serde_json::to_string_pretty(outcome).unwrap())
            }
            FrameworkOutcome::Error { framework, .. } => {
                (framework, serde_json::to_string_pretty(outcome).unwrap())
            }
            FrameworkOutcome::Skipped { framework, .. } => {
                (framework, serde_json::to_string_pretty(outcome).unwrap())
            }
        };
        let path = results_dir.join(format!("{model}_{fw}.json"));
        if let Err(e) = std::fs::write(&path, &content) {
            eprintln!("Warning: failed to save {}: {e}", path.display());
        }
    }

    // Also save a combined summary.
    let summary_path = results_dir.join(format!("{model}_summary.json"));
    let summary = serde_json::to_string_pretty(outcomes).unwrap();
    if let Err(e) = std::fs::write(&summary_path, &summary) {
        eprintln!("Warning: failed to save summary: {e}");
    }

    eprintln!();
    eprintln!("Results saved to {}/", results_dir.display());
}

/// Compute error metrics between two logit sample vectors.
fn compute_errors(a: &[f64], b: &[f64]) -> (f64, f64, f64, f64) {
    let n = a.len().min(b.len());
    if n == 0 {
        return (0.0, 0.0, 0.0, 0.0);
    }
    let mut max_err = 0.0f64;
    let mut sum_abs = 0.0f64;
    let mut sum_sq = 0.0f64;
    let mut sum_ref_sq = 0.0f64;
    for i in 0..n {
        let diff = (a[i] - b[i]).abs();
        max_err = max_err.max(diff);
        sum_abs += diff;
        sum_sq += diff * diff;
        sum_ref_sq += a[i] * a[i];
    }
    let mae = sum_abs / n as f64;
    let rmse = (sum_sq / n as f64).sqrt();
    let rel = if sum_ref_sq > 0.0 {
        (sum_sq / sum_ref_sq).sqrt()
    } else {
        0.0
    };
    (max_err, mae, rmse, rel)
}

fn compare_outputs(results: &[&BenchResult]) {
    if results.len() < 2 {
        return;
    }
    let reference = results[0];
    // Skip detailed comparison if PyTorch (ground truth) isn't the reference.
    if reference.framework != "pytorch" {
        eprintln!();
        eprintln!(
            "=== Output comparison skipped (no PyTorch ground truth, reference: {}) ===",
            reference.framework
        );
        return;
    }
    eprintln!();
    eprintln!(
        "=== Output comparison (reference: {}) ===",
        reference.framework
    );
    eprintln!(
        "  {:<12} {:>12} {:>12} {:>12} {:>12} {:>12}  {}",
        "Framework", "Loss Diff", "Max Error", "MAE", "RMSE", "Rel Error", "Status"
    );
    eprintln!("  {}", "-".repeat(90));
    for other in &results[1..] {
        let hash_match = reference.outputs.logits_hash == other.outputs.logits_hash;
        let loss_diff = (reference.outputs.loss - other.outputs.loss).abs();
        // Normalize by reference loss: for AR-heavy models the absolute loss is
        // larger, so we need proportionally larger absolute thresholds.
        // max(abs, 1.0) keeps thresholds sane when the loss is near zero.
        let norm = reference.outputs.loss.abs().max(1.0);
        let rel_loss = loss_diff / norm;
        let (max_err, mae, rmse, rel) = compute_errors(
            &reference.outputs.logits_sample,
            &other.outputs.logits_sample,
        );
        let status = if hash_match {
            "EXACT MATCH"
        } else if rel_loss < 0.01 && rel < 0.01 {
            "PASS (<1% rel)"
        } else if rel_loss < 0.05 || (rel_loss < 0.10 && rel < 0.1) {
            "CLOSE"
        } else {
            "DIFFERENT MODEL"
        };
        eprintln!(
            "  {:<12} {:>12.6e} {:>12.6e} {:>12.6e} {:>12.6e} {:>12.6e}  {}",
            other.framework, loss_diff, max_err, mae, rmse, rel, status
        );
    }
}

/// Determine which frameworks "match" the reference (first successful result).
/// Returns a set of framework names that passed correctness checks.
/// Uses PyTorch as the reference (ground truth). If PyTorch isn't present,
/// all frameworks are considered matching (caller handles this case).
fn matching_frameworks(successes: &[&BenchResult]) -> std::collections::HashSet<String> {
    let mut matching = std::collections::HashSet::new();
    if successes.is_empty() {
        return matching;
    }
    // Find PyTorch as ground truth; fall back to first framework.
    let reference = successes
        .iter()
        .find(|r| r.framework == "pytorch")
        .unwrap_or(&successes[0]);
    matching.insert(reference.framework.clone());
    for other in &successes[1..] {
        let loss_diff = (reference.outputs.loss - other.outputs.loss).abs();
        let norm = reference.outputs.loss.abs().max(1.0);
        let rel_loss = loss_diff / norm;
        let (_, _, _, rel) = compute_errors(
            &reference.outputs.logits_sample,
            &other.outputs.logits_sample,
        );
        // Match if loss is close. Normalize by reference loss so that
        // AR-heavy models (with larger absolute loss) get proportionally
        // larger absolute thresholds.
        if rel_loss < 0.05 || (rel_loss < 0.10 && rel < 0.1) {
            matching.insert(other.framework.clone());
        }
    }
    matching
}

/// Heuristic: does this backend string look like a CPU backend?
/// Matches "CPU", "CPUExecutionProvider", "faster-whisper (CTranslate2, CPU)".
fn is_cpu_backend(backend: &str) -> bool {
    backend.to_uppercase().contains("CPU")
}

fn result_backend<'a>(r: &'a BenchResult) -> &'a str {
    r.extra
        .get("backend")
        .and_then(|v| v.as_str())
        .unwrap_or("")
}

fn print_table(outcomes: &[FrameworkOutcome], successes: &[&BenchResult]) {
    // Check if PyTorch (ground truth) ran successfully.
    let has_pytorch = successes.iter().any(|r| r.framework == "pytorch");

    // If PyTorch ran on a non-CPU backend, skip CPU-only rows from other
    // frameworks — a CPU-vs-GPU comparison isn't meaningful. The reverse
    // (PyTorch on CPU, others on GPU) is fine and stays as-is.
    let pytorch_on_gpu = successes
        .iter()
        .find(|r| r.framework == "pytorch")
        .is_some_and(|r| !is_cpu_backend(result_backend(r)));
    if !has_pytorch && !successes.is_empty() {
        eprintln!();
        eprintln!("⚠ WARNING: PyTorch (ground truth) did not run successfully.");
        eprintln!("  Results are shown but NOT validated against a reference implementation.");
        eprintln!("  Loss-based correctness checks are disabled.");
        eprintln!();
    }

    // Without ground truth, treat all successful frameworks as matching
    // (no strike-through) since we have nothing to compare against.
    let matching = if has_pytorch {
        matching_frameworks(successes)
    } else {
        successes.iter().map(|r| r.framework.clone()).collect()
    };

    // Find best compile/inference/latency/train among matching frameworks.
    let mut best_compile = f64::MAX;
    let mut best_inference = f64::MAX;
    let mut best_latency = f64::MAX;
    let mut best_training = f64::MAX;
    for o in outcomes {
        if let FrameworkOutcome::Ok(r) = o
            && matching.contains(&r.framework)
        {
            if r.timings.compile_s < best_compile {
                best_compile = r.timings.compile_s;
            }
            if r.timings.inference_ms < best_inference {
                best_inference = r.timings.inference_ms;
            }
            if r.timings.latency_ms > 0.0 && r.timings.latency_ms < best_latency {
                best_latency = r.timings.latency_ms;
            }
            if r.timings.training_ms > 0.0 && r.timings.training_ms < best_training {
                best_training = r.timings.training_ms;
            }
        }
    }

    println!(
        "| Platform | Framework | Compile (s) | Inference (ms) | Latency (ms) | Training (ms) | Loss |"
    );
    println!(
        "|----------|-----------|:-----------:|:--------------:|:------------:|:-------------:|:----:|"
    );

    let mut platform_shown = false;
    for outcome in outcomes {
        // Skip CPU-only rows when PyTorch is on GPU.
        if pytorch_on_gpu
            && let FrameworkOutcome::Ok(r) = outcome
            && is_cpu_backend(result_backend(r))
        {
            continue;
        }

        // Show platform (device name) only on the first row.
        let platform = if !platform_shown {
            if let FrameworkOutcome::Ok(r) = outcome {
                platform_shown = true;
                if cfg!(target_os = "windows") {
                    format!("{} (Windows)", r.gpu_name)
                } else {
                    r.gpu_name.clone()
                }
            } else {
                String::new()
            }
        } else {
            String::new()
        };

        match outcome {
            FrameworkOutcome::Ok(r) => {
                let link = framework_md_link(&r.framework, &r.extra);
                let is_matching = matching.contains(&r.framework);

                let fmt_val = |val: f64, best: f64, is_time: bool| -> String {
                    let s = if is_time && val == 0.0 {
                        "—".to_string()
                    } else if is_time && val < 10.0 {
                        // Sub-10ms values need a decimal to distinguish e.g.
                        // 2.5ms inference from 3.4ms training — otherwise both
                        // round to "3" and the visual extension vanishes.
                        format!("{:.1}", val)
                    } else if is_time {
                        format!("{:.0}", val)
                    } else {
                        format!("{:.2}", val)
                    };
                    if !is_matching {
                        format!("~~{s}~~")
                    } else if val > 0.0 && (val - best).abs() < 0.01 {
                        format!("**{s}**")
                    } else {
                        s
                    }
                };

                let compile = fmt_val(r.timings.compile_s, best_compile, false);
                let inference = fmt_val(r.timings.inference_ms, best_inference, true);
                let latency = fmt_val(r.timings.latency_ms, best_latency, true);
                let training = fmt_val(r.timings.training_ms, best_training, true);
                let loss = if is_matching {
                    format!("{:.2}", r.outputs.loss)
                } else {
                    format!("~~{:.2}~~", r.outputs.loss)
                };

                println!(
                    "| {platform} | {link} | {compile} | {inference} | {latency} | {training} | {loss} |"
                );
            }
            FrameworkOutcome::Error { framework, .. } => {
                let (display, url) = framework_meta(framework);
                let link = if url.is_empty() {
                    display.to_string()
                } else {
                    format!("[{display}]({url})")
                };
                println!("| {platform} | {link} | ✗ | ✗ | ✗ | ✗ | |");
            }
            FrameworkOutcome::Skipped { framework, .. } => {
                let (display, url) = framework_meta(framework);
                let link = if url.is_empty() {
                    display.to_string()
                } else {
                    format!("[{display}]({url})")
                };
                println!("| {platform} | {link} | — | — | — | — | |");
            }
        }
    }
}

fn main() {
    let cli = Cli::parse();
    let root = project_root(cli.root.as_deref());

    let frameworks: Vec<&str> = match &cli.frameworks {
        Some(list) => list.iter().map(String::as_str).collect(),
        None => all_frameworks(),
    };

    let mut outcomes = Vec::new();
    for fw in &frameworks {
        outcomes.push(run_framework(&root, fw, &cli.model, cli.dry_run));
    }

    // Collect successful results for comparison.
    let successes: Vec<&BenchResult> = outcomes
        .iter()
        .filter_map(|o| match o {
            FrameworkOutcome::Ok(r) => Some(r),
            _ => None,
        })
        .collect();

    if cli.dry_run {
        // Dry-run: just show support matrix, no table/comparison/save.
        let model = &cli.model;
        eprintln!();
        eprintln!("=== Dry-run: {model} ===");
        for outcome in &outcomes {
            match outcome {
                FrameworkOutcome::Ok(r) => {
                    eprintln!("  ✓ {}", r.framework);
                }
                FrameworkOutcome::Error {
                    framework, error, ..
                } => {
                    let short = error
                        .lines()
                        .next()
                        .unwrap_or(error)
                        .chars()
                        .take(70)
                        .collect::<String>();
                    eprintln!("  ✗ {framework}: {short}");
                }
                FrameworkOutcome::Skipped {
                    framework, reason, ..
                } => {
                    eprintln!("  — {framework}: {reason}");
                }
            }
        }
        return;
    }

    if cli.json {
        println!("{}", serde_json::to_string_pretty(&outcomes).unwrap());
    } else {
        print_table(&outcomes, &successes);
        // Dump each framework error to stderr so users can see what failed
        // instead of staring at a wall of ✗.
        let mut printed_header = false;
        for outcome in &outcomes {
            if let FrameworkOutcome::Error {
                framework, error, ..
            } = outcome
            {
                if !printed_header {
                    eprintln!();
                    eprintln!("=== Framework errors ===");
                    printed_header = true;
                }
                eprintln!("[{framework}] {error}");
            }
        }
    }

    // Save results even when everything fails — the per-framework JSON captures
    // the stderr excerpt, which is often the only record of what went wrong.
    save_results(&root, &cli.model, &outcomes);

    if successes.is_empty() {
        eprintln!("No successful benchmark results.");
        std::process::exit(1);
    }

    compare_outputs(&successes);
}
