# Fred-LLM Features

This document tracks all features - implemented and planned. Check off items as they are completed.

---

## Core Infrastructure

- [x] Project scaffolding - Complete Python project structure with uv/hatchling ✅ **Working with uv**
- [x] CLI interface - Typer-based CLI with rich output formatting ✅ **Tested: dataset, run, evaluate commands**
- [x] Configuration system - YAML-based config with Pydantic validation ✅ **3 example configs + complete template**
- [x] **Pipeline System** ✅ **January 3, 2026 - Production ready**
  - [x] Data preparation workflow - Raw → augment → split → convert → prompts ✅ **Tested: 5750 equations, 5 formats**
  - [x] Inference workflow - Prompts → LLM → evaluate ✅ **Ready for production**
  - [x] Config-first design - Main CLI with YAML configs ✅ **Simplified from 7 to 3 configs**
  - [x] Format auto-detection - From filenames and content analysis ✅ **Tested: 6/6 passing**
  - [x] Flexible prompting - Pre-generated or on-the-fly generation ✅
  - [x] Dry run mode - Preview execution plan ✅ **Tested on all workflows**
  - [x] Pydantic validation - Smart config validation with helpful errors ✅
  - [x] Optional model/evaluation - Can run without LLM (data-only workflows) ✅ **January 3, 2026**
  - [x] Script cleanup - Removed 7 obsolete scripts, kept 2 internal runners ✅ **January 3, 2026**
  - [x] Windows compatibility - Fixed Unicode console encoding ✅ **January 3, 2026**
  - [x] **YAML config ASCII compatibility** ✅ **February 11, 2026**
    - [x] Replaced all Unicode characters (✅, ⚠️, ℹ️, →, box-drawing) with ASCII equivalents
    - [x] Fixed cp1252 encoding errors on Windows
    - [x] All config files now safe for Windows/Linux/Mac
  - [x] **Evaluation-only mode** ✅ **February 12, 2026**
    - [x] Run evaluation on existing LLM predictions without inference
    - [x] EvaluationDataConfig in adaptive_config.py for predictions_path
    - [x] _run_evaluation_only() method in AdaptivePipeline
    - [x] Enhanced CLI evaluate command with tolerance options
    - [x] Documentation in EVALUATION_PIPELINE.md and QUICKSTART.md
    - [x] Example configs and sample data in examples/
    - [x] Data formats reference in DATA_FORMATS_REFERENCE.md
  - [x] **Global seed management for reproducibility** ✅ **February 13, 2026**
    - [x] Centralized set_global_seed() function in src/utils/random_seed.py
    - [x] Controls: Python random, NumPy, TensorFlow, PyTorch, OS environment
    - [x] CLI parameter: --seed flag for run command with override capability
    - [x] Config support: seed field in dataset.raw section of YAML configs
    - [x] Default seed: 42 across all configs for reproducible results
    - [x] Affects: Data augmentation, train/test splitting, evaluation point generation
    - [x] Usage: `uv run python -m src.cli run --config config.yaml --seed 12345`
  - [ ] Caching intermediate results - Save prepared data and prompts for reuse 🚧 **Outputs saved but no checkpointing**
  - [ ] Resume capability - Continue from last successful stage ❌
- [x] Logging utilities - Structured logging with file output support ✅ **Working in all modules**
- [ ] Experiment tracking - MLflow or Weights & Biases integration ❌ **Not started**
- [ ] Caching layer - Cache LLM responses for reproducibility ❌ **Not started**
- [ ] Parallel processing - Concurrent batch evaluation ❌ **Not started**
- [ ] REST API - Serve model as web service ❌ **Not started**

## Data Pipeline

- [x] Dataset fetcher - Download Fredholm-LLM dataset from Zenodo ✅ **Tested: Downloads 5K sample (37MB), all commands working**
- [x] Fredholm loader - Specialized loader with expression type inference ✅ **Tested: 5000 equations, type analysis complete**
- [x] Generic data loader - JSON/JSONL file loading with filtering ✅ **Tested: Format detection works**
- [x] Format converter - LaTeX and RPN conversion utilities ✅ **Tested: Infix↔LaTeX↔RPN (5000/5000 success, no errors)**
- [x] **Formatter Architecture (8 formatters total)** ✅ **All tested with 18 formatter tests passing**
  - [x] Basic formatters (Infix, LaTeX, RPN, Python, Tokenized) ✅
  - [x] Fredholm equation formatter - Complete equation formatting ✅ **Supports infix, latex, rpn**
  - [x] Tokenized equation formatter - Special tokens for LLM training ✅ **<LAMBDA>, <INT>, <LOWER>, <UPPER>, <SEP>**
  - [x] Series formatters (Taylor series, Neumann series) ✅ **Approximation-based solutions**
  - [x] Expression canonicalization - Simplify parameter ✅ **Available in all formatters**
  - [x] CSV export support - Export formatted equations to CSV ✅ **Matches original dataset format**
- [x] Data augmentation framework - 14 edge case strategies ✅ **Tested: all 14 edge case strategies**
- [x] **Edge case augmentations (14 strategies, 42 variants, 15% target ratio)** ✅ **Tested on 5K sample: 750 augmented (15.0%)**
  - [x] No-solution cases - 4 strategies: eigenvalue, range_violation, divergent_kernel, disconnected_support ✅ **Tested: 12 variants total**
  - [x] Numerical-only cases - 8 strategies: complex_kernels, weakly_singular, boundary_layer, oscillatory, mixed_type, compact_support, near_resonance, neumann_series ✅ **Tested: 24 variants total**
  - [x] Regularization-required cases - Fredholm 1st kind requiring regularization ✅ **Tested: 3 variants, ill-posed handling, has_solution=True**
  - [x] Non-unique-solution cases - Exact resonance with solution families ✅ **Tested: 3 variants, symbolic u=C*φ**
  - [x] Resonance split - **resonance** (exact, family) vs **near_resonance** (ill-conditioned, discrete_points) ✅ **January 2, 2026**
  - [x] Compact support split - **compact_support** (approx_coef) vs **disconnected_support** (no solution) ✅ **January 2, 2026**
  - [x] Disconnected support kernels use valid Piecewise expressions ✅ **February 11, 2026**
  - [x] **All augmentation kernels use parseable SymPy expressions** ✅ **February 11, 2026**
    - [x] Replaced placeholder strings ("Piecewise: nonzero in...") with valid Piecewise syntax
    - [x] Converted ternary operators ("t if t <= x else x") to Piecewise notation
    - [x] Fixed 5 augmentation files: disconnected_support, mixed_type, compact_support (2 cases), neumann_series
    - [x] All kernel definitions now SymPy-parseable for LaTeX conversion
  - [x] **Solution type refactoring: 5→7 types** ✅ **January 3, 2026**
    - [x] Split `exact` → `exact_symbolic` (formula) (removed `exact_coef` as redundant)
    - [x] Split `numerical` → `approx_coef` (functional form) + `discrete_points` (samples) + `series` (expansions)
    - [x] Keep `family`, `regularized`, `none` unchanged
    - [x] New strategy: **neumann_series** (4-term Neumann expansions) → `series` type
    - [x] Rationale: Clear pedagogical signals, different evaluation methods, mathematical rigor
    - [x] Updated: All 18 augmentation files, splitter.py, augmentation.py, validator.py
    - [x] **Removed `exact_coef`** (mathematically identical to `family`, impossible to evaluate)
    - [x] **Folder reorganization** ✅ **January 3, 2026**
      - [x] Renamed folders to match solution type taxonomy
      - [x] OLD: no_solution/, numerical_only/, regularization_required/, non_unique_solution/
      - [x] NEW: exact_symbolic/, approx_coef/, discrete_points/, series/, family/, regularized/, none_solution/
      - [x] Updated: All __init__.py files, augmentation.py strategy groups, README.md
      - [x] Distribution: 18 strategies across 7 folders (4+5+2+1+1+1+4)
  - [x] Validation - Comprehensive checks for all 14 strategies and 7 solution types ✅ **Integrated in pipeline**
  - [x] Empty string handling - `u=""` for equations without analytical solutions ✅ **Fixed: all augmentation files**
  - [x] **Edge case metadata management** ✅ **January 3, 2026**
    - [x] Default: Essential fields only (u, f, kernel, augmentation_type, solution_type, edge_case, reason, recommended_methods)
    - [x] Optional: 60+ detailed technical fields (singularity details, boundary layers, oscillations, etc.)
    - [x] CLI flag: `--include-edge-metadata` to include all technical metadata
    - [x] Clean output: Null values (None in JSON, "" in CSV) for unset fields, not deleted
    - [x] Rationale: Cleaner default output for LLM training, full details available for research
- [x] Data validator - Validate equation syntax and solvability ✅ **Tested: 100/100 equations validated, 0 errors**
- [x] **Evaluation points filtering - Overflow-safe numeric evaluation** ✅ **February 11, 2026**
  - [x] NumPy error suppression - Ignore overflow/invalid/divide warnings during lambdify evaluation
  - [x] Non-finite filtering - Drop inf/nan values from exp, cosh overflows
  - [x] Critical point inclusion - Boundaries, midpoint, near-boundary points
  - [x] Fallback handling - Raise error if all points produce non-finite values
  - [x] Fixed in base.py _generate_evaluation_points() - Used by all has_solution=True augmentations
  - [x] Persist evaluation_points in dataset outputs ✅ **February 12, 2026**
- [x] **Dataset splitting with stratification (sklearn + pandas)** ✅ **Tested: 19 tests, all passing**
  - [x] Stratified splitting - Maintains balance across original/augmented, solution types, edge cases ✅
  - [x] Flexible split ratios - 80/0/20 default, custom ratios supported ✅
  - [x] Edge case handling - Invalid ratios (auto-adjust), single item, 100% train, empty datasets ✅
  - [x] Reproducible splits - Seed-based reproducibility for consistent train/val/test ✅
  - [x] Split statistics - Analysis of balance across all splits ✅
- [x] **Stratified sampling for balanced test sets** ✅ **February 12, 2026**
  - [x] Sample N equations per solution type for diverse testing ✅
  - [x] Config support in raw.stratified_sample and prepared.stratified_sample ✅
  - [x] CLI support via --stratified-sample and --samples-per-type flags ✅
  - [x] Automatic solution type detection and balancing ✅
  - [x] Example config: configs/stratified_sample.yaml ✅
  - [x] **Correct pipeline order: Load → Augment → Sample → Split** ✅
  - [x] Samples from augmented data (includes edge cases!) ✅
  - [x] Use case: Create test sets with 1 sample per type (diverse) or N samples per type (balanced) ✅
- [ ] Special function augmentation - Add Bessel, Legendre equations ❌ **Not started**
- [ ] Numeric ground truth - SciPy-based numerical solutions ❌ **Not started**

## LLM Integration

- [x] **OpenAI API support** - GPT-4, GPT-3.5, GPT-4o ✅ **Complete API integration, tested (January 29, 2026)**
  - [x] API key management - Environment variable (OPENAI_API_KEY) or config override ✅
  - [x] Model selection - Dynamic model_name parameter ✅
  - [x] Request/response handling - OpenAI SDK with retry logic ✅
  - [x] Cost tracking - Automatic token and USD tracking ✅ **Using openai-cost-calculator**
- [x] **OpenRouter API support** - Claude, Llama, Mistral, Gemini, etc. ✅ **Complete API integration, tested (January 29, 2026)**
  - [x] API key management - Environment variable (OPENROUTER_API_KEY) or config override ✅
  - [x] Model routing - Access 200+ models through unified API ✅
  - [x] Request/response handling - OpenAI-compatible SDK ✅
  - [x] Cost tracking - Native usage.cost from API ✅ **Direct from OpenRouter**
- [x] **Cost Tracking System** ✅ **Complete implementation (January 29, 2026)**
  - [x] Per-call tracking - Tokens (prompt/completion/cached), cost in USD, timestamp ✅
  - [x] Run aggregation - Total cost, requests, tokens by provider and model ✅
  - [x] Cost calculation - OpenAI (openai-cost-calculator), OpenRouter (native usage.cost) ✅
  - [x] Financial precision - Decimal type for accurate USD arithmetic ✅
  - [x] Detailed logging - Per-call JSONL logs with full metadata ✅
  - [x] Summary reports - JSON summaries with provider/model breakdowns ✅
  - [x] Terminal output - Rich table display of costs during runs ✅
  - [x] Test coverage - 10 tests for calculators, tracker, and runner integration ✅ **All passing**
- [x] Local model support - HuggingFace placeholder ⚠️ **Scaffolded but TODO: Model loading not implemented**
- [x] Batch generation - Process multiple equations efficiently ✅ **With rate limiting**
- [x] **Agentic multi-method solver** ✅ **July 7, 2026 - see docs/AGENTIC_SOLVER.md**
  - [x] 5 parallel method agents (degenerate_kernel, adomian, neumann, fredholm_alternative, numerical) ✅
  - [x] Deterministic SymPy residual verification (reuses verify_solution, no GT leak) ✅
  - [x] Feedback-driven repair round for failed candidates ✅
  - [x] Deterministic selection: verified > majority vote > best effort ✅
  - [x] Config via model.agentic section; same predictions schema → baseline-comparable ✅
  - [x] Per-equation trace file (agentic_trace_*.jsonl) with candidates and verdicts ✅
  - [x] Test coverage - 8 tests with mocked base runner ✅ **All passing**
- [ ] Fine-tuning support - Train custom models (Phi, T5) ❌ **Not started**
- [ ] Tool-assisted solving - LLM generates Python code for SymPy ❌ **Not started**
- [ ] Iterative refinement - Multi-turn conversation for complex equations ❌ **Not started**
- [ ] Confidence scoring - Estimate solution reliability ⚠️ **Basic scoring in postprocess.py**

## Prompt Engineering

- [x] Basic/direct prompts - Simple equation-to-solution prompts ✅ **Implemented via src/prompts/styles/basic.py**
- [x] Chain-of-thought prompts - Step-by-step reasoning ✅ **Implemented via src/prompts/styles/chain_of_thought.py**
- [x] Few-shot prompts - Include worked examples ✅ **Implemented via src/prompts/styles/few_shot.py**
- [x] **Refactored prompt_templates.py** ✅ **February 13, 2026**
  - [x] Moved from src/llm/prompt_templates.py to src/prompts/prompt_templates.py
  - [x] Legacy support with note to use OOP-based styles
  - [x] Updated imports in src/cli.py and tests/test_prompting.py
  - [x] Removed duplicate FEW_SHOT_EXAMPLES definitions
- [x] Tool-assisted prompts - Enable tool use for computation ✅ **Template defined in src/prompts/styles/tool_assisted.py**
- [x] **Prompt generation system** ✅ **Complete modular architecture (January 1, 2026)**
  - [x] PromptStyle ABC - Base class with 4 implementations (basic, CoT, few-shot, tool-assisted) ✅
  - [x] BatchPromptProcessor - Batch processing with progress tracking ✅
  - [x] CSV to JSONL pipeline - Load equations, generate prompts, save metadata ✅
  - [x] CLI commands - Integrated in main pipeline with rich output ✅
  - [x] Format support - Works with infix, latex, rpn formats ✅
  - [x] Ground truth inclusion - Optional solution embedding for evaluation ✅
  - [x] Metadata preservation - Includes equation_id, style, format, domain ✅
  - [x] **Edge case modes** - 3 modes for handling edge cases ✅ **(January 2, 2026)**
    - `none`: Pure inference, no edge case instructions
    - `guardrails`: Brief instruction to state if no solution exists
    - `hints`: Include `has_solution` and `solution_type` in prompt
  - [x] **Structured output format** - Standardized LLM response format for evaluation ✅ **(January 3, 2026)**
    - All 4 prompt styles specify SOLUTION:/HAS_SOLUTION:/SOLUTION_TYPE: format
    - Enables reliable extraction of solution correctness and edge case recognition
    - Postprocessor with regex patterns for has_solution (yes/no) and solution_type (7 types)
    - Evaluation metrics: solution correctness, has_solution accuracy, solution_type classification (7-class)
  - [x] **Format-specific prompt generation** - Prompts tailored to dataset format ✅ **(January 3, 2026)**
    - System detects format from filename (*_infix.csv, *_latex.csv, *_rpn.csv)
    - Each prompt includes targeted instructions for that specific format only
    - Infix: "Express solution in infix notation (x**2 + sin(x))"
    - LaTeX: "Express solution in LaTeX notation (x^2 + \sin(x))"
    - RPN: "Express solution in RPN notation (x 2 ^ x sin +)"
    - Benefits: Clearer instructions, no ambiguity, format-specific training
  - [x] **Solution-type-specific output formats** ⏳ **In Progress (February 11, 2026)**
    - [x] discrete_points format specification: "Format: [(x1, y1), (x2, y2), ...]" ✅ **Completed in 4 prompt styles**
    - [x] discrete_points parser: `extract_discrete_points()` in postprocess.py ✅ **Completed with 11 passing tests**
    - [x] series format specification: "Format: 4 explicit terms in SOLUTION" **February 12, 2026**
    - Benefits: Structured LLM output enables reliable parsing, consistent evaluation, type-specific metrics
  - [x] Test coverage - 30 prompt tests + 11 discrete_points parser tests ✅ **All passing**
- [ ] Approximation prompts - Request series/polynomial approximations ❌ **Not started**
- [ ] Step-by-step breakdown - Decompose complex kernels ❌ **Not started**
- [ ] Error correction prompts - Self-correction mechanisms ❌ **Not started**
- [ ] Template optimization - A/B testing for prompt effectiveness ❌ **Not started**

## Evaluation

- [x] Symbolic evaluation - SymPy-based expression comparison ✅ **Implemented in evaluate.py**
- [x] Numeric evaluation - MAE, MSE, RMSE metrics ✅ **Implemented in evaluate.py**
  - Uses stored evaluation_points when available ✅ **February 12, 2026**
- [x] **Relative L2 error (rel_l2)** - Scale-invariant numeric error metric ✅ **February 13, 2026**
  - rel_l2 = ||pred - true||₂ / ||true||₂ (standard from PDEBench, CodePDE)
  - Aggregated in summary as mean_rel_l2 across all solutions
  - Automatically computed in numeric_compare() 
  - Handles zero ground truth case (returns inf/0 appropriately)
  - Integrated with SolutionEvaluator.summary()
- [x] **Aggregated numeric metrics in reports** ✅ **February 13, 2026**
  - Mean MAE, RMSE, mean error, and max error reported in CLI and metrics JSON
- [x] **Residual verification x sampling uses evaluation_points** ✅ **February 13, 2026**
  - Uses dataset evaluation_points.x_values when available
  - Falls back to reproducible random sampling otherwise
- [x] **Residual verification reports MAE/RMSE** ✅ **February 13, 2026**
  - Adds residual_mae and residual_rmse to per-sample results
  - Aggregates mean_residual_mae and mean_residual_rmse
- [x] Math-Verify integration - LaTeX parsing + fast-path symbolic verification ✅ **Adapter + fallback parsing**
- [x] Postprocessing - Math-Verify extraction with regex fallback ✅ **Multi-strategy u(x)/SOLUTION parsing**
- [x] **Structured output extraction** - Parse has_solution and solution_type from LLM responses ✅ **(January 3, 2026)**
  - _extract_has_solution(): Regex patterns for yes/no classification with validation
  - _extract_solution_type(): Regex patterns for 7-class solution type recognition
  - Return format: {"solution_str", "solution_sympy", "has_solution", "solution_type", "reasoning", "confidence", "raw_response"}
- [x] **discrete_points parser** - Extract point lists from LLM responses ✅ **(February 11, 2026)**
  - extract_discrete_points(): Parses [(x1, y1), (x2, y2), ...] format
  - Integrated with parse_llm_output() for automatic detection
  - Handles scientific notation, negative values, extra whitespace
  - Validation: minimum 2 points, finite values (<1e10)
  - Test coverage: 11 unit tests covering all formats and edge cases
- [x] **discrete_points evaluation** - Point-wise comparison metrics ✅ **(February 12, 2026)**
  - evaluate_discrete_points(): Compares predicted vs ground truth discrete points
  - Metrics: matched_points (count), accuracy (%), max_error, mean_error, RMSE
  - Tolerance-based matching: x_tolerance (default 1e-3), y_tolerance (configurable)
  - Classification: 80% threshold for "match" status
  - Integrated with SolutionEvaluator.evaluate_discrete_points_type()
  - Test coverage: 13 unit tests covering matching, tolerance, edge cases
- [x] **series term-by-term evaluation** - Per-term numeric RMSE ✅ **(February 12, 2026)**
  - evaluate_series_terms(): Compares series terms by index using numeric RMSE
  - Metadata: series_term_count, series_term_match, series_term_stats
  - Integrated with SolutionEvaluator.evaluate() when solution_type is series
- [x] **approx_coef term comparison** - Per-term coefficient errors ✅ **(February 12, 2026)**
  - evaluate_approx_coeffs(): Compares coefficients per top-level term
  - Metadata: approx_coef_eval, approx_coef_stats
  - Integrated with SolutionEvaluator.evaluate() when solution_type is approx_coef
- [x] **Per-equation evaluation details** ✅ **(February 12, 2026)**
  - Evaluated predictions include symbolic/numeric match flags and per-point arrays
- [x] **family numeric evaluation (multi-sample)** ✅ **(February 12, 2026)**
  - Numeric comparison across multiple constant samples
  - Evaluation points store constant_samples and u_values_samples
  - Includes std for max/mean/rmse across samples
- [x] **family termwise evaluation** ✅ **(February 12, 2026)**
  - Term-by-term numeric comparison after constant substitution
  - Metadata: family_term_eval
- [x] **family parameter metadata** - Count + naming validation ✅ **(February 12, 2026)**
- [x] **Edge case evaluation metrics** - has_solution + solution_type accuracy ✅ **(February 6, 2026)**
  - [x] has_solution accuracy (binary classification: TP/TN/FP/FN)
  - [x] solution_type accuracy (7-class: exact_symbolic, approx_coef, discrete_points, series, family, regularized, none)
  - [x] confusion_matrix for solution_type misclassifications ✅ **(February 12, 2026)**
  - [ ] Edge case recognition rate (% of edge cases correctly identified) ❌ **Not implemented**
- [x] **BLEU score** - Token-level string similarity metric ✅ **February 13, 2026**
  - bleu_score(pred_str, gt_str): Computes NLTK sentence_bleu with smoothing
  - Tokenizes math expressions by splitting on operators (+, -, *, /, ^, parentheses, etc.)
  - Returns float in [0.0, 1.0]; handles empty strings gracefully (returns 0.0)
  - Integrated with SolutionEvaluator.evaluate() when pred_str and gt_str provided
  - Aggregated in summary as mean_bleu across all solutions
  - Test coverage: 7 unit tests covering identical, different, partial, empty cases
- [x] **extract_operators()** - Operator set extraction from SymPy expressions ✅ **February 13, 2026**
  - Recursively walks expression tree to collect operators (sin, cos, tan, exp, log, sqrt, Add, Mul, Pow, Integral, etc.)
  - Returns set of operator names for structural comparison
  - Used by operator_f1 for precision/recall computation
  - Test coverage: 5 unit tests for polynomials, trig, nested, constants, symbols
- [x] **operator_f1()** - Operator set-based F1 metric ✅ **February 13, 2026**
  - operator_f1(pred_expr, gt_expr): Computes precision, recall, F1 based on operator sets
  - Supports both expressions with operators and pure constants (F1=1.0 for both empty)
  - Returns: {"precision", "recall", "f1", "pred_ops", "gt_ops"}
  - Integrated with SolutionEvaluator.evaluate() for all solution types
  - Aggregated in summary as mean_operator_precision, mean_operator_recall, mean_operator_f1
  - Test coverage: 6 unit tests for identical, disjoint, partial overlap, constants, superset cases
- [x] **None-type detection metrics** - Precision/recall/F1 for no-solution classification ✅ **February 13, 2026**
  - Tracks TP (none correctly predicted), FP (false "no solution"), FN (missed none-type)
  - Computes precision = TP/(TP+FP), recall = TP/(TP+FN), F1 = 2PR/(P+R)
  - Integrated with evaluate_solutions() for batch evaluation
  - Returns metrics["none_detection"] = {"precision", "recall", "f1", "tp", "fp", "fn"}
  - Test coverage: 6 unit tests for perfect detection, missed, false positive, mixed scenarios
- [x] **Residual verification** - Fredholm equation solution verification ✅ **February 13, 2026**
  - verify_solution(solution, kernel, f, lambda, domain): Checks u(x) - λ ∫K(x,t)u(t)dt = f(x)
  - Tries symbolic integration first, falls back to numericintegration on 50-point grid
  - Returns {"verified", "residual_max", "residual_mean"} 
  - Integrated with evaluate_solutions() when kernel/f/lambda metadata available
  - Aggregated in metrics["residual_verification"] with verified_count/rate and mean residuals
- [ ] Robustness testing - Prompt variation sensitivity ❌ **Not started**
- [ ] Generalization testing - Performance on unseen function types ❌ **Not started**
- [ ] Benchmark suite - Standardized evaluation dataset ❌ **Not started**

## Output Formats

- [x] Symbolic output - Mathematical expressions
- [ ] Series expansion output - Taylor/Fourier series solutions
- [ ] Code output - Executable Python/SymPy code
- [ ] LaTeX export - Publication-ready formatted solutions
- [x] Interactive notebooks - Data exploration notebook with visualizations

## Data Exploration

- [x] Dataset overview tables - Column info, types, sample values ✅
- [x] Expression length analysis - Min/max/mean/median for u, f, kernel ✅
- [x] Expression type distribution - Polynomial, trig, hyperbolic, etc. ✅
- [x] Numerical parameter analysis - λ, a, b statistics and histograms ✅
- [x] Solution type classification - Trivial, constant, linear, polynomial, etc. ✅
- [x] Augmented dataset analysis - Original vs augmented balance, edge case distribution ✅ **Section 7: 5 subsections**
- [x] Edge case type breakdown - 12 edge case types with examples ✅ **Deep dive into no_solution, ill_posed, etc.**
- [x] Sample equations viewer - Display examples from each category ✅ **Shows originals + edge case types**
- [x] Dataset summary statistics - Quick overview with validation checks ✅ **Balance, solution types, quality metrics**
- [ ] Kernel complexity analysis - Nested function depth, term count ❌
- [ ] Solvability assessment - Existence of closed-form solutions ❌

## Configuration Presets

- [x] default.yaml - Standard balanced settings
- [x] development.yaml - Fast iteration for testing
- [x] production.yaml - Full evaluation settings
- [x] local.yaml - Self-hosted model settings
- [x] openrouter.yaml - OpenRouter with popular models
- [x] fine_tuning.yaml - Training configuration

## Testing & Documentation

- [x] **Unit tests** - 238 tests covering core functionality ✅ **Math-Verify coverage added**
  - [x] Core data tests - loader, validator, splitter, augmentation, formatters (104 tests)
  - [x] API key tests - Environment variables and config overrides (15 tests)
  - [x] Cost tracking tests - Calculators, tracker, and integration (10 tests)
- [x] Math-Verify adapter tests - Parsing, extraction, comparison, integration ✅ **29 tests**
- [x] Formatter tests - 19 tests for all formatters including series formatters ✅ **All passing**
- [x] Augmentation tests - 21 tests for all augmentation strategies ✅ **All passing**
  - [x] 14 edge case augmentation strategies tested
  - [x] **Unified 18-field schema** - ALL augmentations output identical keys
  - [x] 14 edge case strategies organized in 6 solution-type folders
  - [x] 8 advanced edge case tests (weakly_singular through compact_support)
  - [x] Schema validation tests - Verify all 18 required fields present
  - [x] Strategy separation - resonance (family) vs near_resonance (discrete_points) ✅ **January 2, 2026**
  - [x] Validation tooling - validator.py with augmented data validation ✅ **January 3, 2026**
    - Basic equation validation (kernel, f, lambda, domain, solution)
    - Augmented data validation (edge cases, solution types, pattern consistency)
    - Custom validation rules support
- [x] Validation tests - 5 tests for data validation and integration ✅ **All passing**
- [x] Splitting tests - 19 tests for stratified splitting with sklearn ✅ **All passing**
  - [x] Standard ratio tests - 80/0/20, 80/10/10, custom ratios
  - [x] Data integrity tests - No overlap, all items preserved, reproducibility
  - [x] Edge case tests - Empty list, single item, 100% train, invalid ratios
  - [x] Stratification tests - Maintains balance, solution types, edge cases, no leakage
  - [x] Statistics tests - get_split_statistics functionality
- [x] Pipeline diagram - Mermaid-based architecture visualization
- [x] README - Comprehensive project documentation
- [x] Config README - Configuration usage guide
- [x] Formatter README - Detailed formatter documentation with examples
- [x] Features tracking - This document
- [ ] Integration tests - End-to-end pipeline testing ❌ **Not started**
- [ ] API reference - Auto-generated from docstrings ❌ **Not started**
- [ ] Tutorial notebooks - Step-by-step usage examples ❌ **Not started**
- [ ] Contribution guide - How to add new features ❌ **Not started**

---

## Progress Summary

| Category | Done | Total | Progress |
|----------|------|-------|----------|
| Core Infrastructure | 4 | 8 | 50% |
| Data Pipeline | 6 | 9 | 67% |
| LLM Integration | 4 | 8 | 50% |
| Prompt Engineering | 5 | 9 | 56% |
| Evaluation | 5 | 9 | 56% |
| Output Formats | 2 | 5 | 40% |
| Data Exploration | 5 | 7 | 71% |
| Configuration | 6 | 6 | 100% |
| **Total** | **42** | **69** | **61%** |

---

## Testing Results (February 13, 2026)

### 🧪 Unit Tests

Test suite size: **~300+ tests** (including new evaluation tests)

**Test Coverage:**
- `test_fredholm_loader.py` - 13 tests: FredholmEquation class, type inference, CSV parsing
- `test_loader.py` - 7 tests: DataLoader, JSON/JSONL loading, filtering, batching
- `test_model_runner.py` - 13 tests: Model runner initialization, factory pattern, batch generation
- `test_prompting.py` - 7 tests: Prompt template generation, formatting, examples
- `test_formatters.py` - 19 tests: All formatters including series approximations
- `test_augmentation.py` - 21 tests: Basic and edge case augmentation strategies
- `test_validation.py` - 5 tests: Data validation and integration
- `test_splitting.py` - 19 tests: Stratified splitting with sklearn/pandas
- `test_prompt_generation.py` - 30 tests: Prompt styles, edge case modes, batch processing
- `test_math_verify_adapter.py` - 29 tests: Math-Verify parsing, extraction, compare, and fallbacks
- **`test_evaluate.py` - 60+ tests (February 13, 2026):**
  - **TestBleuScore** - 7 tests: Identical strings, different strings, partial matches, empty cases, score bounds
  - **TestExtractOperators** - 5 tests: Polynomials, trig, nested functions, constants, single symbols
  - **TestOperatorF1** - 6 tests: Identical operators, disjoint sets, partial overlap, constants, supersets
  - **TestNoneDetectionPRF1** - 6 tests: Perfect detection, missed, false positives, mixed scenarios  
  - **TestSymbolicCompare** - 4 tests: Identical, equivalent, different, trig identities
  - **TestNumericCompare** - 3+ tests: Identical functions, close functions, different functions, custom domains
  - **TestVerifySolution** - 2 tests: Simple valid solutions, error handling
  - **TestSolutionEvaluator** - 10+ tests: Single solutions, summaries, series/approx_coef metadata, family evaluation
  - **TestEvaluateSolutions** - 9+ tests: File loading, JSON/JSONL, parse error handling, edge cases
  - Plus: RelativeL2, DiscretePoints, SeriesTerms, ApproxCoef evaluation tests

All core components validated at unit level.

### ✅ Dataset Splitting - PRODUCTION READY

**Stratified Splitting with scikit-learn + pandas** (January 1, 2026)

- **Implementation**: Industry-standard ML libraries (sklearn's `train_test_split`, pandas DataFrames)
- **Default Split**: 80/0/20 (train/validation/test)
- **Stratification**: Maintains balance across:
  - Original vs augmented equations (86.7% / 13.3%)
  - Solution types (exact_symbolic, approx_coef, discrete_points, series, family, regularized, none)
  - Edge case types (14 strategies, 42 variants)
- **Edge Case Handling**:
  - Invalid ratios → Auto-adjust to valid proportions
  - Single item datasets → Assign to train split
  - 100% train split → Early return without sklearn
  - Small strata (<2 samples) → Fallback to non-stratified
  - Empty datasets → Return empty lists
- **Test Coverage**: 19 tests covering all scenarios
- **Architecture**: Clean module separation (`src/data/splitter.py` with proper exports)

### ✅ Data Pipeline - WORKING

Successfully tested the complete data pipeline workflow:

1. **Dataset Download** - Successfully downloaded 5K sample dataset (37.37 MB) from Zenodo
   - Checksum verification works
   - Auto-extraction from ZIP
   - Sample dataset creation (5000 rows from 500K full set)

2. **Dataset Loading** - FredholmDatasetLoader fully functional
   - Loads CSV with all columns (u, f, kernel, lambda, a, b, type flags)
   - Expression type inference working (real_value, polynomial, trig, hyperbolic, exponential)
   - Statistics generation: 47.1% polynomial, 27.6% real value, 8.4% trig, 8.9% hyperbolic, 8.0% exponential

3. **Format Conversion** - Partially working
   - ✅ Infix → LaTeX conversion works
   - ✅ Infix → RPN conversion works (basic operators and functions)
   - ⚠️ LaTeX parsing requires `antlr4` package (fallback implemented)
   - ⚠️ RPN → SymPy works for basic expressions (needs more operators)

4. **Data Augmentation** - Partially implemented
   - ✅ Framework structure in place
   - ✅ Scale coefficient strategy implemented
   - ❌ Variable substitution - TODO
   - ❌ Domain shifting - TODO
   - ❌ Kernel composition - TODO

### ⚠️ LLM Integration - SCAFFOLDED BUT NOT FUNCTIONAL

The model runners are well-structured but incomplete:

- **OpenAIModelRunner** - Class exists, API calls commented out as TODO
- **OpenRouterModelRunner** - Class exists, API calls commented out as TODO
- **LocalModelRunner** - Class exists, model loading commented out as TODO
- **Batch generation** - Structure exists, needs rate limiting and error handling

**Action needed**: Implement actual API calls and model loading to make these functional.

### ✅ Prompt Templates - COMPLETE

All prompt styles are implemented and ready to use:
- Basic prompts
- Chain-of-thought prompts
- Few-shot prompts (with example support)
- Tool-assisted prompts (for future tool use)

System prompts and user templates all defined.

### ✅ Evaluation - IMPLEMENTED

- Symbolic comparison with SymPy (simplify, expand, trigsimp)
- Numeric comparison with numpy (MAE, MSE, RMSE, max error)
- Math-Verify parsing and extraction with regex fallback for LLM outputs

### ❌ Main Pipeline - NOT FUNCTIONAL

The `FredLLMPipeline.run()` method is scaffolded but all internal methods return empty lists:
- `_load_data()` - TODO
- `_generate_prompts()` - TODO
- `_run_inference()` - TODO
- `_postprocess()` - TODO
- `_evaluate()` - TODO

**To make functional**: Connect the working components (loaders, prompt templates, model runners, evaluators).

### CLI Commands Status

| Command | Status | Notes |
|---------|--------|-------|
| `dataset download` | ✅ Working | Downloads from Zenodo, creates samples |
| `dataset info` | ✅ Working | Shows schema and file info |
| `dataset stats` | ✅ Working | Expression type distribution |
| `dataset sample` | ✅ Working | Shows 5 example equations |
| `run` | ⚠️ Partial | Loads config, but pipeline methods are TODO |
| `evaluate` | ⚠️ Scaffolded | Structure exists, needs implementation |
| `convert` | ⚠️ Scaffolded | Structure exists, needs implementation |
| `prompt` | ⚠️ Scaffolded | Structure exists, needs implementation |

---

## Version History

### v0.2.0 (In Progress)

**✅ Verified data pipeline end-to-end (download → load → stats → sample)
- ✅ Tested format conversion utilities
- ✅ Ran full test suite: 40/40 tests passing (100%)
- ✅ Documented implementation gaps with detailed status indicators
- ✅ Updated FEATURES.md with comprehensive testing result
- Updated FEATURES.md with detailed status

**Remaining work for v0.2.0:**
- Implement actual LLM API calls in model runners
- Connect components in main pipeline
- Complete data augmentation strategies
- Add missing CLI command implementations

### v0.1.0 (Current)

- Initial project scaffolding
- Dataset fetching from Zenodo
- Multi-provider LLM support (OpenAI, OpenRouter, Local)
- Basic prompt templates (direct, chain-of-thought, few-shot)
- Symbolic and numeric evaluation
- CLI with run, evaluate, convert, prompt, dataset commands
- 40 unit tests passing

