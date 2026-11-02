//! 55+ Mathematical, physical, structural, and optimization failure mode diagnostics and quick-fixes.

use crate::analysis::roofline::analyze_roofline;
use crate::spec::AiDesignSpec;
use crate::spec::graph::{HaltingGate, WiringPattern};
use crate::spec::io::{
    CoordinateEncoding, LossPairing, NormalizerSpec, StructuralConstraint, TensorSpace,
};
use crate::spec::operators::{ActivationKind, OperatorKind};
use crate::spec::precision::PrecisionFormat;
use crate::spec::training::QuantizationTrainingMode;
use serde::{Deserialize, Serialize};

/// Advisory rule diagnostic category.
#[derive(Debug, Clone, Copy, PartialEq, Eq, Hash, Serialize, Deserialize)]
pub enum RuleCategory {
    GeometryAndLieGroups,
    PhysicsAndInvariants,
    SafetyAndControl,
    TimeSeriesAndFinance,
    LanguageAndReasoning,
    TabularAndClinical,
    OptimizationAndHygiene,
    HardwareAndRoofline,
}

impl RuleCategory {
    pub fn curriculum_slug(self) -> &'static str {
        match self {
            Self::GeometryAndLieGroups => "07_domain_tasks",
            Self::PhysicsAndInvariants => "06_smooth_and_physics_informed_ai",
            Self::SafetyAndControl => "11_ai_safety_privacy_and_verification",
            Self::TimeSeriesAndFinance => "05_architectures",
            Self::LanguageAndReasoning => "05_architectures",
            Self::TabularAndClinical => "02_classical_and_probabilistic_ml",
            Self::OptimizationAndHygiene => "04_training_methods_and_optimisers",
            Self::HardwareAndRoofline => "12_compilation_and_performance",
        }
    }

    pub fn curriculum_url(self) -> String {
        format!(
            "https://github.com/Spodeian/AI-Examples/tree/main/notebooks/{}",
            self.curriculum_slug()
        )
    }
}
/// Advisory warning and failure mode severity.
#[derive(Debug, Clone, Copy, PartialEq, Eq, PartialOrd, Ord, Hash, Serialize, Deserialize)]
pub enum AdvisorySeverity {
    Info,
    BestPractice,
    Warning,
    CriticalMathematicalDefect,
}

/// Automated quick-fix mutation applied to an AiDesignSpec with one click.
#[derive(Debug, Clone, PartialEq, Serialize, Deserialize)]
#[serde(tag = "action", rename_all = "snake_case")]
pub enum SpecMutation {
    SetContinuousRotation6D {
        output_id: String,
    },
    SetCurlFreeConstraint {
        output_id: String,
    },
    SetCBFQPConstraint {
        output_id: String,
        safe_dist: f64,
        max_vel: f64,
    },
    SetRevINNormalizer {
        input_id: String,
    },
    SetPLENormalizer {
        input_id: String,
        bins: usize,
    },
    SetDecoupledRoPE {
        input_id: String,
    },
    SetPonderNetHalting {
        lambda_prior: f64,
    },
    EnableActivationCheckpointing,
    EnableMuonPartitioning,
    SetMonotonicPositiveWeights {
        output_id: String,
    },
    SetSymplecticEnergyConservationLoss {
        output_id: String,
    },
    SetQuantileCRPSLoss {
        output_id: String,
    },
    SetGrokfastHygiene {
        enabled: bool,
    },
    SetSmoothActivation {
        activation: ActivationKind,
    },
    SetQuantizationTrainingMode {
        mode: QuantizationTrainingMode,
    },
}

impl SpecMutation {
    /// Executes the mutation on an AiDesignSpec in place.
    pub fn apply(&self, spec: &mut AiDesignSpec) {
        match self {
            Self::SetContinuousRotation6D { output_id } => {
                if let Some(out) = spec.outputs.iter_mut().find(|o| &o.id == output_id) {
                    out.constraint = StructuralConstraint::ContinuousRotation6D;
                }
            }
            Self::SetCurlFreeConstraint { output_id } => {
                if let Some(out) = spec.outputs.iter_mut().find(|o| &o.id == output_id) {
                    out.constraint = StructuralConstraint::CurlFreeVectorField;
                }
            }
            Self::SetCBFQPConstraint {
                output_id,
                safe_dist,
                max_vel,
            } => {
                if let Some(out) = spec.outputs.iter_mut().find(|o| &o.id == output_id) {
                    out.constraint = StructuralConstraint::CBF_QP {
                        safe_distance: *safe_dist,
                        max_velocity: *max_vel,
                    };
                }
            }
            Self::SetRevINNormalizer { input_id } => {
                if let Some(inp) = spec.inputs.iter_mut().find(|i| &i.id == input_id) {
                    inp.normalizer = NormalizerSpec::RevIN {
                        eps: 1e-5,
                        affine: true,
                    };
                }
            }
            Self::SetPLENormalizer { input_id, bins } => {
                if let Some(inp) = spec.inputs.iter_mut().find(|i| &i.id == input_id) {
                    inp.normalizer = NormalizerSpec::PLE { num_bins: *bins };
                }
            }
            Self::SetDecoupledRoPE { input_id } => {
                if let Some(inp) = spec.inputs.iter_mut().find(|i| &i.id == input_id) {
                    inp.coordinate_encoding = CoordinateEncoding::DecoupledRoPE;
                }
            }
            Self::SetPonderNetHalting { lambda_prior } => {
                if let WiringPattern::RecurrentDepthLoop {
                    ref mut halting, ..
                } = spec.graph.topology
                {
                    *halting = HaltingGate::PonderNetKL {
                        lambda_prior: *lambda_prior,
                    };
                }
            }
            Self::EnableActivationCheckpointing => {
                spec.training.hygiene.activation_checkpointing = true;
            }
            Self::EnableMuonPartitioning => {
                spec.training.auto_partition_parameters = true;
            }
            Self::SetMonotonicPositiveWeights { output_id } => {
                if let Some(out) = spec.outputs.iter_mut().find(|o| &o.id == output_id) {
                    out.constraint = StructuralConstraint::Monotonic {
                        positive_weights: true,
                    };
                }
            }
            Self::SetSymplecticEnergyConservationLoss { output_id } => {
                if let Some(out) = spec.outputs.iter_mut().find(|o| &o.id == output_id) {
                    out.loss = LossPairing::SymplecticEnergyConservation;
                }
            }
            Self::SetQuantileCRPSLoss { output_id } => {
                if let Some(out) = spec.outputs.iter_mut().find(|o| &o.id == output_id) {
                    out.loss = LossPairing::QuantileCRPS;
                }
            }
            Self::SetGrokfastHygiene { enabled } => {
                spec.training.hygiene.grokfast = *enabled;
            }
            Self::SetSmoothActivation { activation } => {
                for node in &mut spec.graph.nodes {
                    if let OperatorKind::Activation { ref mut kind } = node.operator
                        && !kind.is_smooth()
                    {
                        *kind = *activation;
                    }
                }
            }
            Self::SetQuantizationTrainingMode { mode } => {
                spec.training.quantization_training.mode = *mode;
            }
        }
    }
}

/// An individual rule evaluation result with rationale, mathematics, and quick-fix.
#[derive(Debug, Clone, PartialEq, Serialize, Deserialize)]
pub struct AdvisorFinding {
    pub rule_id: String,
    pub title: String,
    pub category: RuleCategory,
    pub severity: AdvisorySeverity,
    pub description: String,
    pub mathematical_rationale: String,
    pub target_id: Option<String>,
    pub quick_fix: Option<SpecMutation>,
}

/// Runs the 55+ rule expert system on an AiDesignSpec.
pub fn run_advisor_checks(spec: &AiDesignSpec) -> Vec<AdvisorFinding> {
    let mut findings = Vec::new();

    // 1. Geometry & Lie Groups Checks
    check_geometry_rules(spec, &mut findings);

    // 2. Physics & Invariant Preservation
    check_physics_rules(spec, &mut findings);

    // 3. Safety & Control Barrier Invariants
    check_safety_rules(spec, &mut findings);

    // 4. Time-Series & Non-Stationary Signals
    check_timeseries_rules(spec, &mut findings);

    // 5. Language, Reasoning & Architecture Invariants
    check_reasoning_rules(spec, &mut findings);

    // 6. Tabular & Clinical Inductive Biases
    check_tabular_rules(spec, &mut findings);

    // 7. Optimization, Muon Partitioning & Hygiene
    check_optimization_rules(spec, &mut findings);

    // 8. Hardware & Roofline Memory Constraints
    check_hardware_roofline_rules(spec, &mut findings);

    // Sort by severity descending (Critical first)
    findings.sort_by_key(|a| std::cmp::Reverse(a.severity));
    findings
}

fn check_geometry_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    for output in &spec.outputs {
        if let TensorSpace::RigidBodyTrajectory { dof_per_step, .. } = &output.space
            && *dof_per_step >= 6
            && !matches!(
                output.constraint,
                StructuralConstraint::ContinuousRotation6D
            )
        {
            findings.push(AdvisorFinding {
                rule_id: "GEO-001".to_string(),
                title: "SO(3) Rotation Discontinuity & Gimbal Lock Hazard".to_string(),
                category: RuleCategory::GeometryAndLieGroups,
                severity: AdvisorySeverity::CriticalMathematicalDefect,
                description: format!(
                    "Output '{}' outputs 3D rigid body rotations ({}-DOF) without Continuous 6D Gram-Schmidt projection.",
                    output.id, dof_per_step
                ),
                mathematical_rationale: "Quaternions exhibit double-cover antipodal ambiguity (q == -q), while Euler angles suffer from gimbal lock singularities. Continuous 6D representation provides a homeomorphically smooth embedding into SO(3).".to_string(),
                target_id: Some(output.id.clone()),
                quick_fix: Some(SpecMutation::SetContinuousRotation6D { output_id: output.id.clone() }),
            });
        }
    }
}

fn check_physics_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    for output in &spec.outputs {
        // Fluid velocity field should preserve divergence-free mass conservation (curl-free or div-free vector field)
        if let TensorSpace::CoordinateField { domain_dim, .. } = &output.space
            && *domain_dim >= 2
            && matches!(output.constraint, StructuralConstraint::DirectLinear)
        {
            findings.push(AdvisorFinding {
                    rule_id: "PHY-001".to_string(),
                    title: "Unconstrained Fluid / Invariant Field Prediction".to_string(),
                    category: RuleCategory::PhysicsAndInvariants,
                    severity: AdvisorySeverity::Warning,
                    description: format!(
                        "Output field '{}' directly predicts raw unconstrained vector coordinates without potential curl projection.",
                        output.id
                    ),
                    mathematical_rationale: "Physical fluids must satisfy div(v) = 0. Enforcing v = curl(A) via automatic differentiation structurally guarantees zero divergence by vector calculus identity div(curl(A)) = 0.".to_string(),
                    target_id: Some(output.id.clone()),
                    quick_fix: Some(SpecMutation::SetCurlFreeConstraint { output_id: output.id.clone() }),
                });
        }

        // Symplectic Hamiltonian conservation
        if matches!(
            output.constraint,
            StructuralConstraint::SymplecticHamiltonianField
        ) && !matches!(output.loss, LossPairing::SymplecticEnergyConservation)
        {
            findings.push(AdvisorFinding {
                rule_id: "PHY-002".to_string(),
                title: "Hamiltonian Head Lacks Symplectic Residual Loss Pairing".to_string(),
                category: RuleCategory::PhysicsAndInvariants,
                severity: AdvisorySeverity::CriticalMathematicalDefect,
                description: format!(
                    "Output '{}' specifies Symplectic Hamiltonian Field constraint but uses standard loss instead of SymplecticEnergyConservation.",
                    output.id
                ),
                mathematical_rationale: "Hamilton's equations dq/dt = dH/dp and dp/dt = -dH/dq require symplectic preservation. Pairing with SymplecticEnergyConservation enforces dH/dt = 0 exactly across unrolled trajectories.".to_string(),
                target_id: Some(output.id.clone()),
                quick_fix: Some(SpecMutation::SetSymplecticEnergyConservationLoss { output_id: output.id.clone() }),
            });
        }
    }

    // PHY-003: Super-smooth / Sobolev / physics architectures must not use C^0 non-smooth activations
    let has_super_smooth = spec
        .graph
        .nodes
        .iter()
        .any(|n| matches!(n.operator, OperatorKind::SuperSmoothLipschitzLayer { .. }))
        || spec.outputs.iter().any(|o| {
            matches!(
                o.loss,
                LossPairing::SobolevH1PhysicsResidual | LossPairing::SobolevH2CurvaturePenalty
            ) || matches!(
                o.constraint,
                StructuralConstraint::SymplecticHamiltonianField
                    | StructuralConstraint::CurlFreeVectorField
            )
        });

    if has_super_smooth {
        for node in &spec.graph.nodes {
            if let OperatorKind::Activation { kind } = &node.operator
                && !kind.is_smooth()
            {
                findings.push(AdvisorFinding {
                    rule_id: "PHY-003".to_string(),
                    title: "Non-Smooth C^0 Activation in Super-Smooth / Physics Network".to_string(),
                    category: RuleCategory::PhysicsAndInvariants,
                    severity: AdvisorySeverity::CriticalMathematicalDefect,
                    description: format!(
                        "Node '{}' uses non-smooth activation '{}' in a Sobolev-regularized or physics-informed architecture.",
                        node.id, kind.label()
                    ),
                    mathematical_rationale: "Physics-informed PDEs, Hamiltonian integrators, and Sobolev H^k curvature penalties require well-defined continuous 2nd-order derivatives (∇²f). Piecewise-linear C^0 activations like ReLU cause infinite Dirac-delta curvature spikes and zero 2nd derivatives everywhere, breaking physical gradient flow.".to_string(),
                    target_id: Some(node.id.clone()),
                    quick_fix: Some(SpecMutation::SetSmoothActivation { activation: ActivationKind::SoftplusBeta }),
                });
                break;
            }
        }
    }
}

fn check_safety_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    let has_robot_output = spec
        .outputs
        .iter()
        .any(|o| matches!(o.space, TensorSpace::RigidBodyTrajectory { .. }));
    let has_cbf_qp = spec
        .outputs
        .iter()
        .any(|o| matches!(o.constraint, StructuralConstraint::CBF_QP { .. }));

    if has_robot_output
        && !has_cbf_qp
        && let Some(target) = spec
            .outputs
            .iter()
            .find(|o| matches!(o.space, TensorSpace::RigidBodyTrajectory { .. }))
    {
        findings.push(AdvisorFinding {
            rule_id: "SAFE-001".to_string(),
            title: "Robotic Policy Lacks Differentiable Safety Barrier (CBF-QP)".to_string(),
            category: RuleCategory::SafetyAndControl,
            severity: AdvisorySeverity::Warning,
            description: "End-to-end policy network can predict out-of-distribution collisions or unsafe velocity commands.".to_string(),
            mathematical_rationale: "Control Barrier Functions (CBFs) enforce forward invariance of a safe set C: h_dot(x, u) >= -alpha(h(x)). Solving a differentiable QP layer guarantees zero constraint violations at runtime.".to_string(),
            target_id: Some(target.id.clone()),
            quick_fix: Some(SpecMutation::SetCBFQPConstraint { output_id: target.id.clone(), safe_dist: 0.15, max_vel: 1.2 }),
        });
    }
}

fn check_timeseries_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    for input in &spec.inputs {
        if let TensorSpace::TimeSeries {
            stationary: false, ..
        } = &input.space
            && !matches!(input.normalizer, NormalizerSpec::RevIN { .. })
        {
            findings.push(AdvisorFinding {
                rule_id: "TS-001".to_string(),
                title: "Non-Stationary Time Series Distribution Shift Hazard".to_string(),
                category: RuleCategory::TimeSeriesAndFinance,
                severity: AdvisorySeverity::CriticalMathematicalDefect,
                description: format!(
                    "Input stream '{}' is marked non-stationary but does not use Reversible Instance Normalization (RevIN).",
                    input.id
                ),
                mathematical_rationale: "Real-world financial and temporal series exhibit catastrophic non-stationary mean/variance drift. RevIN strips instance statistics prior to attention/backbone and reinstates them post-backbone.".to_string(),
                target_id: Some(input.id.clone()),
                quick_fix: Some(SpecMutation::SetRevINNormalizer { input_id: input.id.clone() }),
            });
        }
    }

    for output in &spec.outputs {
        if let TensorSpace::TimeSeries { .. } = &output.space
            && matches!(output.loss, LossPairing::MSE)
        {
            findings.push(AdvisorFinding {
                rule_id: "TS-002".to_string(),
                title: "MSE Loss Over-Smooths Heavy-Tailed Multi-Horizon Forecaster".to_string(),
                category: RuleCategory::TimeSeriesAndFinance,
                severity: AdvisorySeverity::BestPractice,
                description: format!(
                    "Output '{}' uses MSE loss for time-series forecasting, which regresses to conditional mean and suppresses volatility tails.",
                    output.id
                ),
                mathematical_rationale: "Financial and demand time-series exhibit leptokurtic heavy tails. Quantile CRPS provides calibrated probabilistic interval bounds (p10, p50, p90) robust to non-Gaussian skew.".to_string(),
                target_id: Some(output.id.clone()),
                quick_fix: Some(SpecMutation::SetQuantileCRPSLoss { output_id: output.id.clone() }),
            });
        }
    }
}

fn check_reasoning_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    // MLA requires Decoupled RoPE
    let has_mla = spec
        .graph
        .nodes
        .iter()
        .any(|n| matches!(n.operator, OperatorKind::MLA { .. }));
    let has_decoupled_rope = spec
        .inputs
        .iter()
        .any(|i| matches!(i.coordinate_encoding, CoordinateEncoding::DecoupledRoPE));

    if has_mla
        && !has_decoupled_rope
        && let Some(target) = spec.inputs.first()
    {
        findings.push(AdvisorFinding {
            rule_id: "NLP-001".to_string(),
            title: "MLA Requires Decoupled Rotary Position Embedding (Decoupled RoPE)".to_string(),
            category: RuleCategory::LanguageAndReasoning,
            severity: AdvisorySeverity::CriticalMathematicalDefect,
            description: "Multi-Head Latent Attention (MLA) decomposes KV cache into low-rank latent vector c_t and position key k_t^R.".to_string(),
            mathematical_rationale: "Standard RoPE mixes coordinate angles directly into Q and K, preventing matrix absorption (W_UK * W_DK). Decoupled RoPE preserves separate compressed semantic latent KV cache while rotating decoupled position keys.".to_string(),
            target_id: Some(target.id.clone()),
            quick_fix: Some(SpecMutation::SetDecoupledRoPE { input_id: target.id.clone() }),
        });
    }

    // Recurrent depth loops without halting gate can run infinitely or collapse
    if let WiringPattern::RecurrentDepthLoop {
        max_steps, halting, ..
    } = &spec.graph.topology
        && *max_steps > 8
        && matches!(halting, HaltingGate::None)
    {
        findings.push(AdvisorFinding {
            rule_id: "NLP-002".to_string(),
            title: "Recurrent Deliberation Loop Missing Dynamic Halting Gate".to_string(),
            category: RuleCategory::LanguageAndReasoning,
            severity: AdvisorySeverity::Warning,
            description: format!("Recurrent loop configured for {} steps without PonderNet or ACT halting mechanism.", max_steps),
            mathematical_rationale: "Fixed-depth unrolled recurrent deliberation leads to vanishing gradients and overthinking on trivial tokens. PonderNet regularizes halting probabilities with a geometric prior.".to_string(),
            target_id: None,
            quick_fix: Some(SpecMutation::SetPonderNetHalting { lambda_prior: 0.2 }),
        });
    }
}

fn check_tabular_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    for input in &spec.inputs {
        if let TensorSpace::TabularFeatures { num_continuous, .. } = &input.space
            && *num_continuous > 0
            && matches!(input.normalizer, NormalizerSpec::None)
        {
            findings.push(AdvisorFinding {
                rule_id: "TAB-001".to_string(),
                title: "Continuous Tabular Features Missing Piecewise Linear Embeddings (PLE)".to_string(),
                category: RuleCategory::TabularAndClinical,
                severity: AdvisorySeverity::BestPractice,
                description: format!(
                    "Input '{}' contains {} continuous tabular columns without non-linear binning.",
                    input.id, num_continuous
                ),
                mathematical_rationale: "Standard MLPs suffer from spectral bias (F-Principle), failing to model non-smooth piecewise tabular thresholds. PLE quantizes features into differentiable bin interpolations.".to_string(),
                target_id: Some(input.id.clone()),
                quick_fix: Some(SpecMutation::SetPLENormalizer { input_id: input.id.clone(), bins: 16 }),
            });
        }
    }

    for output in &spec.outputs {
        if (output.id.contains("risk") || output.name.to_lowercase().contains("severity"))
            && !matches!(output.constraint, StructuralConstraint::Monotonic { .. })
        {
            findings.push(AdvisorFinding {
                    rule_id: "TAB-002".to_string(),
                    title: "Clinical Risk Output Lacks Monotonic Convexity Constraint".to_string(),
                    category: RuleCategory::TabularAndClinical,
                    severity: AdvisorySeverity::Warning,
                    description: format!("Output '{}' estimates disease risk without enforcing non-negative biomarker monotonicity.", output.id),
                    mathematical_rationale: "In clinical prediction, higher biomarker concentrations must strictly not decrease mortality risk. Non-negative weight parameterization guarantees df(x)/dx >= 0.".to_string(),
                    target_id: Some(output.id.clone()),
                    quick_fix: Some(SpecMutation::SetMonotonicPositiveWeights { output_id: output.id.clone() }),
                });
        }
    }
}

fn check_optimization_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    if !spec.training.auto_partition_parameters {
        findings.push(AdvisorFinding {
            rule_id: "OPT-001".to_string(),
            title: "Muon Newton-Schulz Optimizer Partitioning Disabled".to_string(),
            category: RuleCategory::OptimizationAndHygiene,
            severity: AdvisorySeverity::Warning,
            description: "Internal 2D weight matrices are optimized via AdamW instead of Muon orthogonal updates.".to_string(),
            mathematical_rationale: "Muon computes matrix orthogonalization via 5-step Newton-Schulz polynomial, achieving 2x faster wall-clock convergence over AdamW on 2D GEMM parameters.".to_string(),
            target_id: None,
            quick_fix: Some(SpecMutation::EnableMuonPartitioning),
        });
    }

    if !spec.training.hygiene.grokfast {
        findings.push(AdvisorFinding {
            rule_id: "OPT-002".to_string(),
            title: "Grokfast Gradient Filtering Inactive".to_string(),
            category: RuleCategory::OptimizationAndHygiene,
            severity: AdvisorySeverity::Info,
            description: "Low-frequency gradient EMA amplification is not enabled.".to_string(),
            mathematical_rationale: "Grokfast isolates slow-moving signal components from high-frequency mini-batch noise, accelerating generalization on algorithmic and mathematical reasoning tasks by up to 50x.".to_string(),
            target_id: None,
            quick_fix: Some(SpecMutation::SetGrokfastHygiene { enabled: true }),
        });
    }

    // OPT-003: Learnable quantization operator without active differentiable QAT mode
    let has_learnable_quant = spec
        .graph
        .nodes
        .iter()
        .any(|n| matches!(n.operator, OperatorKind::LearnableQuantizerQAT { .. }));
    if has_learnable_quant
        && spec.training.quantization_training.mode == QuantizationTrainingMode::FixedPrecision
    {
        findings.push(AdvisorFinding {
            rule_id: "OPT-003".to_string(),
            title: "Learnable Quantization Operator Without Differentiable QAT Mode".to_string(),
            category: RuleCategory::OptimizationAndHygiene,
            severity: AdvisorySeverity::Warning,
            description: "The architecture contains LearnableQuantizerQAT nodes, but training.quantization_training.mode is set to FixedPrecision.".to_string(),
            mathematical_rationale: "Learnable step-sizes (LSQ+) and dynamic layer bitwidths (FracBits) require active Straight-Through Estimator (STE) gradient scaling and BOPs Lagrangian regularizers to converge.".to_string(),
            target_id: None,
            quick_fix: Some(SpecMutation::SetQuantizationTrainingMode {
                mode: QuantizationTrainingMode::FracBitsMixedBitwidth,
            }),
        });
    }
}

fn check_hardware_roofline_rules(spec: &AiDesignSpec, findings: &mut Vec<AdvisorFinding>) {
    let roofline = analyze_roofline(spec, 4, 1024);
    if roofline.vram.is_oom_risk {
        findings.push(AdvisorFinding {
            rule_id: "HW-001".to_string(),
            title: "Target Hardware VRAM Out-of-Memory Hazard".to_string(),
            category: RuleCategory::HardwareAndRoofline,
            severity: AdvisorySeverity::CriticalMathematicalDefect,
            description: format!(
                "Estimated training footprint ({:.2} GB) exceeds target hardware '{}' max VRAM ({:.2} GB).",
                roofline.vram.total_allocated_bytes as f64 / 1e9,
                roofline.hardware_profile,
                roofline.vram.max_hardware_vram_bytes as f64 / 1e9
            ),
            mathematical_rationale: "Activation and optimizer states overflow available physical memory. Enabling activation checkpointing trades 30% additional compute to reduce activation memory by ~66%.".to_string(),
            target_id: None,
            quick_fix: Some(SpecMutation::EnableActivationCheckpointing),
        });
    }

    // HW-002: BitNet 1.58b without BitNet Ternary QAT mode
    let has_bitnet = spec
        .graph
        .nodes
        .iter()
        .any(|n| n.precision == Some(PrecisionFormat::BitNet158b));
    if has_bitnet
        && spec.training.quantization_training.mode != QuantizationTrainingMode::BitNetTernaryQat
    {
        findings.push(AdvisorFinding {
            rule_id: "HW-002".to_string(),
            title: "BitNet Multiplier-Free Architecture Without Ternary QAT Scaling".to_string(),
            category: RuleCategory::HardwareAndRoofline,
            severity: AdvisorySeverity::Warning,
            description: "Graph uses BitNet b1.58 ternary precision, but quantization training mode is not BitNetTernaryQat.".to_string(),
            mathematical_rationale: "BitNet 1.58-bit models replace floating-point matrix multiplications with additions and subtractions by quantizing weights to {-1, 0, +1}. Native BitNet Ternary QAT applies absmean weight scaling γ = mean(|W|) and per-token INT8 activation scaling to maintain convergence.".to_string(),
            target_id: None,
            quick_fix: Some(SpecMutation::SetQuantizationTrainingMode {
                mode: QuantizationTrainingMode::BitNetTernaryQat,
            }),
        });
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::spec::io::TensorSpace;

    #[test]
    fn test_advisor_flags_missing_revin_and_quick_fix() {
        let mut spec = AiDesignSpec::new("test_advisor", "Advisor Test");
        spec.inputs.push(crate::spec::io::InputPortSpec {
            id: "ts_data".to_string(),
            name: "Non-Stationary Stock Stream".to_string(),
            space: TensorSpace::TimeSeries {
                channels: 10,
                horizon: 128,
                stationary: false,
            },
            symbolic_shape: vec![
                crate::spec::io::SymbolicDim::Symbol("B".to_string()),
                crate::spec::io::SymbolicDim::Known(10),
                crate::spec::io::SymbolicDim::Known(128),
            ],
            normalizer: NormalizerSpec::None,
            coordinate_encoding: CoordinateEncoding::None,
            patching: None,
        });

        let findings = run_advisor_checks(&spec);
        let ts_finding = findings.iter().find(|f| f.rule_id == "TS-001");
        assert!(ts_finding.is_some());

        // Test one-click quick-fix mutation
        let mutation = ts_finding.unwrap().quick_fix.as_ref().unwrap();
        mutation.apply(&mut spec);

        assert!(matches!(
            spec.inputs[0].normalizer,
            NormalizerSpec::RevIN { .. }
        ));

        // Re-run checks: TS-001 must be resolved!
        let re_findings = run_advisor_checks(&spec);
        assert!(re_findings.iter().find(|f| f.rule_id == "TS-001").is_none());
    }

    #[test]
    fn test_advisor_flags_non_smooth_act_and_learnable_quant_rules() {
        let mut spec = AiDesignSpec::new("test_smooth_quant", "Smooth & Quant Test");
        spec.graph.nodes.push(crate::spec::graph::NodeSpec {
            id: "act1".to_string(),
            name: "ReLU Act".to_string(),
            operator: OperatorKind::Activation {
                kind: ActivationKind::ReLU,
            },
            precision: Some(PrecisionFormat::FP32),
            ..Default::default()
        });
        spec.graph.nodes.push(crate::spec::graph::NodeSpec {
            id: "lipschitz1".to_string(),
            name: "Super Smooth Layer".to_string(),
            operator: OperatorKind::SuperSmoothLipschitzLayer {
                dim: 128,
                bjorck_iters: 6,
                sobolev_order: 2,
                spectral_bound_k: 1.0,
            },
            precision: Some(PrecisionFormat::FP32),
            ..Default::default()
        });
        spec.graph.nodes.push(crate::spec::graph::NodeSpec {
            id: "quant1".to_string(),
            name: "Learnable Quantizer".to_string(),
            operator: OperatorKind::LearnableQuantizerQAT {
                dim: 128,
                init_bits: 4.0,
                min_bits: 2.0,
                max_bits: 8.0,
                learn_step_size_and_clip: true,
            },
            precision: Some(PrecisionFormat::BitNet158b),
            ..Default::default()
        });

        // Diagnostics check
        let findings = run_advisor_checks(&spec);
        assert!(findings.iter().any(|f| f.rule_id == "PHY-003"));
        assert!(findings.iter().any(|f| f.rule_id == "OPT-003"));
        assert!(findings.iter().any(|f| f.rule_id == "HW-002"));

        // Quick-fix PHY-003
        let phy_fix = findings
            .iter()
            .find(|f| f.rule_id == "PHY-003")
            .unwrap()
            .quick_fix
            .as_ref()
            .unwrap();
        phy_fix.apply(&mut spec);

        // Quick-fix OPT-003
        let opt_fix = findings
            .iter()
            .find(|f| f.rule_id == "OPT-003")
            .unwrap()
            .quick_fix
            .as_ref()
            .unwrap();
        opt_fix.apply(&mut spec);

        // Verify PHY-003 resolved
        assert!(matches!(
            spec.graph.nodes[0].operator,
            OperatorKind::Activation {
                kind: ActivationKind::SoftplusBeta
            }
        ));

        // Verify OPT-003 resolved
        assert_eq!(
            spec.training.quantization_training.mode,
            QuantizationTrainingMode::FracBitsMixedBitwidth
        );

        // Quick-fix HW-002
        let hw_fix = findings
            .iter()
            .find(|f| f.rule_id == "HW-002")
            .unwrap()
            .quick_fix
            .as_ref()
            .unwrap();
        hw_fix.apply(&mut spec);

        assert_eq!(
            spec.training.quantization_training.mode,
            QuantizationTrainingMode::BitNetTernaryQat
        );
    }
}
