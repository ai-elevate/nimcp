# NIMCP: Exploring Architectural Approaches to AI Safety Through Neuromorphic Design

**Braun Brelin**
AI Elevate
braun.brelin@ai-elevate.ai

**With development assistance from Claude (Anthropic)**

*Working paper -- March 2026*

---

## Abstract

We present NIMCP (Neuromorphic Infant Machine Cognitive Platform), a neuromorphic computing platform that implements biological self-regulation mechanisms as first-class architectural components. Rather than applying safety constraints post-hoc to a capable system, NIMCP embeds safety-relevant properties -- including an adaptive immune system for anomaly detection, homeostatic plasticity for self-regulating learning, developmental staging for capability gating, and ethical reasoning in the decision pipeline -- directly into the system's architecture. Built in C with CUDA acceleration, NIMCP comprises approximately 2,552 source files and 2,456 headers implementing 60+ cognitive modules, 26+ plasticity mechanisms (with 164 plasticity header files), 42 SNN cross-modal bridges, 6 neuromodulators, and 9 biologically-typed synapse models across a multi-layer diamond network topology supporting up to 2 million neurons with 320 inline synapses per neuron. We describe the system's architecture, the neuroscience literature that motivates each safety-relevant component, and the open questions that remain. We do not claim that architectural approaches solve alignment; we argue they deserve rigorous investigation as complements to post-hoc techniques.

---

## 1. Introduction

The dominant paradigm in AI safety research treats alignment as a property to be imposed on already-capable systems. Reinforcement Learning from Human Feedback (RLHF), constitutional AI, red-teaming, and interpretability probes are all applied after a model has been trained. Amodei et al. (2016) identified five concrete problems in AI safety -- avoiding side effects, reward hacking, scalable supervision, safe exploration, and distributional shift -- all framed as challenges for systems whose internal architecture is largely fixed.

We ask a complementary question: **can the architecture itself provide structural safety advantages?**

Biological brains evolved self-regulation mechanisms long before they evolved language or abstract reasoning. Homeostatic plasticity prevents runaway synaptic potentiation (Turrigiano, 2008). Immune-like surveillance detects and suppresses anomalous neural activity. Developmental staging gates the acquisition of complex cognitive capabilities behind demonstrated competence at simpler tasks. These are not post-hoc constraints -- they are load-bearing architecture.

NIMCP implements these mechanisms in a neuromorphic computing platform to study whether they provide meaningful safety properties in artificial systems. The platform is implemented in C with CUDA GPU acceleration and includes:

- A spiking neural network core with biologically-typed synapses (AMPA, NMDA, GABA-A/B, dopamine, serotonin, acetylcholine) and 42 cross-modal bridges
- A liquid neural network (LNN) subsystem with NCP architecture for continuous-time temporal context processing via ODE-based dynamics and adjoint gradient computation
- 60+ cognitive modules inspired by specific neuroscience findings, organized across 33+ specialized brain regions
- 26+ distinct plasticity mechanisms spanning millisecond to day timescales, with 6 neuromodulators (DA, 5-HT, ACh, NE, GABA, Glu)
- A multi-layer diamond network topology (3/5/7 layers) automatically scaled by neuron count
- Hot/cold neuron struct split and sparse synapse storage (320 inline per neuron) for cache-friendly GPU execution
- CPU-staged 2048D semantic embeddings with GPU batch cosine-similarity relevance pipeline
- An adaptive immune system (B cell NAIVE->ACTIVATED->PLASMA progression) that detects and suppresses anomalous activation patterns
- Developmental staging via immersive curriculum (Newborn->Infant->Crawler->Toddler->Child) that gates capability acquisition
- Ethical constraints embedded in the decision pipeline (LGSS, blood-brain barrier, core directives)
- Grounded language system with SNN-Language bridge for biologically-plausible word-concept binding
- 150+ Python API methods for training, inference, and monitoring

This paper describes the architecture, grounds each component in the neuroscience literature, and identifies the open research questions that remain.

---

## 2. Related Work

### 2.1 Neuromorphic Computing

Neuromorphic systems aim to implement brain-inspired computation in hardware or software. The Izhikevich (2003) neuron model demonstrated that simple two-variable models can reproduce the firing patterns of all known cortical neuron types while remaining computationally efficient. Maass, Natschlager, and Markram (2002) introduced Liquid State Machines, showing that recurrent spiking networks can perform real-time computation without stable attractor states.

NIMCP builds on this tradition but extends beyond neural dynamics into cognitive architecture. While most neuromorphic systems focus on efficient spiking computation, NIMCP implements higher-level cognitive functions (ethics, theory of mind, working memory) as modular components integrated with the neural substrate.

### 2.2 Biologically-Inspired Learning

Bi and Poo (1998) established the empirical basis for spike-timing-dependent plasticity (STDP), showing that the relative timing of pre- and postsynaptic spikes determines the direction and magnitude of synaptic change. Pfister and Gerstner (2006) extended this to a triplet rule that accounts for frequency-dependent effects. Turrigiano (2008) characterized homeostatic synaptic scaling as a self-tuning mechanism that maintains stable firing rates. Bienenstock, Cooper, and Munro (1982) proposed the BCM theory with its sliding modification threshold.

NIMCP implements all of these as distinct plasticity modules (Section 5), along with eligibility traces for temporal credit assignment and neuromodulatory gating.

### 2.3 Cognitive Architecture

Baars (1988) proposed Global Workspace Theory (GWT), modeling consciousness as a central broadcast mechanism where modular processors compete for access to a limited-capacity workspace. Dehaene and Naccache (2001) developed the neuronal workspace model, grounding GWT in specific neural circuits. Baddeley and Hitch (1974) established the multi-component model of working memory, with Miller (1956) quantifying its capacity at approximately 7 items.

Tononi (2004) proposed Integrated Information Theory (IIT), measuring consciousness as the quantity Phi -- the amount of integrated information generated by a system above and beyond its parts. Premack and Woodruff (1978) introduced the concept of Theory of Mind -- the ability to attribute mental states to others.

NIMCP implements each of these as concrete software modules (Section 6), connected to the neural substrate through defined interfaces.

### 2.4 AI Safety

Amodei et al. (2016) provided a taxonomy of concrete safety problems. Friston (2010) proposed the Free Energy Principle as a unifying framework for understanding brain function through surprise minimization. NIMCP's predictive processing module implements elements of the Free Energy framework, while the broader safety architecture draws on biological precedent rather than the specific formal frameworks developed in the alignment literature.

---

## 3. System Architecture

### 3.1 Overview

NIMCP is organized in concentric layers:

1. **Public API**: Stable C interface with opaque handles, suitable for language bindings
2. **Brain layer**: Orchestrates all subsystems; manages lifecycle and decision caching
3. **Neural engine**: Neurons, synapses, forward/backward pass, sparse storage
4. **Cognitive modules**: 30+ modules implementing specific cognitive functions
5. **Plasticity system**: 26 mechanisms spanning multiple timescales
6. **GPU backend**: 83 CUDA kernels for parallel computation
7. **Infrastructure**: Memory management, threading, async messaging, error handling

### 3.2 Neural Network Core

The core network implements a multi-layer topology automatically determined by neuron count. Networks with fewer than 5,000 neurons use 3 layers. Medium networks (5K-100K) use 5 layers in a diamond configuration with distribution [17%, 67%, 17%] across hidden layers, creating a wide bottleneck. Large networks (100K+) use 7 layers in a deep diamond [2%, 12%, 36%, 36%, 12%, 2%].

Each neuron maintains:
- Electrophysiological state (membrane potential, threshold, adaptation)
- Learning parameters (STDP, Oja, homeostatic)
- Sparse connectivity via chunked block allocators (97% memory savings over dense arrays)
- Activity tracking via ring buffers (spike history, activity EMA)
- Pluggable neuron model (LIF, Izhikevich, or specialized types)

Layer-aware backbone wiring connects layers sequentially (L0 -> L1 -> L2 -> ... -> Ln) with a budget of 200,000 connections per layer transition.

### 3.3 Synapse Diversity

NIMCP implements 9 biologically-typed synapse models, each with distinct temporal dynamics:

| Type | Time Constant | Biological Role |
|------|--------------|-----------------|
| AMPA | tau = 2ms | Fast excitatory transmission |
| NMDA | tau = 100ms | Slow excitatory; Mg2+ voltage gate; Ca2+ triggers learning |
| GABA-A | tau = 10ms | Fast inhibitory; Cl- channels; drives oscillations |
| GABA-B | tau = 150ms | Slow inhibitory; K+ modulation; G-protein coupled |
| Dopamine | Variable | Reward prediction error signaling |
| Serotonin | Variable | Mood/stability modulation |
| Acetylcholine | Variable | Attention/arousal modulation |
| Electrical | Instantaneous | Bidirectional gap junction |
| Generic | None | Baseline; no dynamics |

This diversity is grounded in Destexhe et al.'s (1994) kinetic models of synaptic receptors, which demonstrated that different receptor types produce qualitatively different postsynaptic responses.

### 3.4 Decision Pipeline

When the system makes a decision, the candidate action passes through multiple safety-relevant stages:

```
Input -> Perception -> Working Memory -> Global Workspace (competition)
    -> Decision Candidate -> Ethics Check (can veto)
    -> Immune Monitoring (can suppress) -> Introspection (coherence)
    -> Action Execution
```

The key architectural property is that safety checks are in the execution path, not optional callbacks.

---

## 4. Safety-Relevant Architecture

### 4.1 Brain Immune System

Inspired by the adaptive immune system, this module maintains a population of detector cells that learn to recognize anomalous activation patterns.

**Biological basis**: The vertebrate adaptive immune system uses clonal selection to amplify effective pathogen detectors while allowing ineffective ones to decay. B cells progress through activation states (naive -> activated -> plasma -> memory), with only mature plasma cells producing antibodies.

**Implementation**: NIMCP maintains populations of B-cell analogs (up to 512) and T-cell analogs (up to 512) that monitor neural activation patterns. When an activation pattern deviates from learned baselines, B cells are activated. T helper cells coordinate the response; T killer cells can quarantine affected neural populations. The system supports inflammation escalation (LOCAL -> REGIONAL -> SYSTEMIC -> STORM) that progressively restricts system capabilities.

**Safety property**: Anomalous activations -- potential hallucinations, runaway feedback loops, out-of-distribution behavior -- trigger immune responses that suppress the aberrant pattern without requiring the specific failure mode to have been anticipated during training.

**Cross-system effects**: Inflammation reduces working memory capacity (by 1-4 items), impairs Theory of Mind processing, affects IIT Phi consciousness metrics, and suppresses learning rate via the unified learning rate composition.

### 4.2 Homeostatic Plasticity

**Biological basis**: Turrigiano (2008) demonstrated that neurons maintain stable firing rates through synaptic scaling -- multiplicatively adjusting all input synaptic weights to compensate for activity perturbations. This prevents runaway potentiation: when LTP at one synapse increases firing, scaling reduces all inputs until the firing rate returns to baseline.

**Implementation**: NIMCP implements three homeostatic mechanisms:

1. **Synaptic scaling**: `scale_factor = (target_rate / actual_rate)^gamma` with soft bounds to prevent saturation
2. **Intrinsic plasticity**: Adjusts firing threshold to maximize output entropy (information transmission)
3. **Metaplasticity**: BCM-like sliding threshold (Bienenstock et al., 1982) where the LTP/LTD crossover point adapts to recent activity

**Safety property**: Learning is structurally self-limiting. The system cannot develop pathologically strong associations through repeated exposure because homeostatic mechanisms automatically compensate.

### 4.3 Developmental Staging

**Biological basis**: Human cognitive development follows a staged progression where complex capabilities emerge only after simpler foundations are established. Piaget's stage theory and subsequent refinements document this progression from sensorimotor coordination through abstract reasoning.

**Implementation**: The developmental training system (`scripts/immerse_athena.py`) implements four stages:

1. **Sensory Awakening** (10,000 stimuli): Self-reconstruction of 1024-dimensional sensory vectors. Plasticity in ACQUISITION mode with full STDP and homeostatic scaling.
2. **Association** (20,000 stimuli): Cross-modal binding via `show_and_name()`. Error signals processed through cerebellum analog.
3. **Conceptual Learning** (30,000 stimuli): Category formation across 100+ facts in science, math, language, history, and ethics.
4. **Reasoning & Dialogue** (open-ended): Complex reasoning, self-reflection, ethical judgment with interactive tutoring.

**Safety property**: Capabilities are gated behind demonstrated competence. The system cannot access advanced capabilities (complex reasoning, multi-modal integration) without stable performance at lower levels, providing natural checkpoints for human oversight.

### 4.4 Ethical Constraints in the Decision Pipeline

**Implementation**: The ethics module evaluates candidate actions against seven violation categories (harm, unfairness, deception, privacy, autonomy, consent, dignity). It is architecturally upstream of action execution -- the module can veto actions, not just flag them. Integration with Theory of Mind enables perspective-based harm assessment.

**Safety property**: Ethical constraints are structural, not a post-processing filter.

**Limitation**: The module implements heuristic rules, not formal ethical reasoning. It cannot handle novel dilemmas outside its rule set.

### 4.5 Introspection and Interpretability

**Biological basis**: Tononi's (2004) Integrated Information Theory proposes that consciousness corresponds to the capacity of a system to integrate information, quantified as Phi.

**Implementation**: The introspection module provides:
- Active neuron population queries
- Compressed internal state vectors
- Epistemic vs. aleatoric uncertainty decomposition (ensemble methods)
- O(1) pattern lookup via hash tables
- Activity history tracking for state trajectory analysis

**Safety property**: The system's internal state is inspectable. Sudden drops in Phi or unexpected state trajectories provide early warning of potential failure modes.

---

## 5. Plasticity System

NIMCP implements 26 distinct plasticity mechanisms coordinated by a central plasticity coordinator. The key mechanisms are:

### 5.1 Triplet STDP

Following Pfister and Gerstner (2006), NIMCP extends classical pairwise STDP with a triplet rule that considers sets of three spikes. The implementation maintains four traces per synapse:

- **r1_pre** (tau = 20ms): Fast presynaptic trace
- **r2_pre** (tau = 113ms): Slow presynaptic trace
- **o1_post** (tau = 34ms): Fast postsynaptic trace
- **o2_post** (tau = 160ms): Slow postsynaptic trace

Weight updates on presynaptic spikes (LTD):
```
dw = -A2_minus * o1_post - A3_minus * r1_pre * o2_post
```

Weight updates on postsynaptic spikes (LTP):
```
dw = A2_plus * r1_pre + A3_plus * r2_pre * o1_post
```

Default parameters follow the visual cortex preset. Trace decay uses exponential functions with denormal flush at 1e-10 to prevent floating-point slowdown.

### 5.2 Eligibility Traces

Three-factor learning enables temporal credit assignment for reinforcement learning:

```
e(t) = lambda^dt * e(t-1) + spike_contribution
dw = learning_rate * e * reward * dopamine
```

This is grounded in the observation that dopaminergic neurons signal reward prediction errors (Schultz et al., 1997), providing the third factor that converts synaptic eligibility into weight change.

### 5.3 Neuromodulatory System

Dopamine, serotonin, and acetylcholine modulate learning and processing. Schultz et al. (1997) established that dopamine neurons encode reward prediction errors. Hasselmo (2006) demonstrated acetylcholine's role in gating encoding vs. retrieval in the hippocampus.

NIMCP implements neuromodulatory effects through the unified learning rate composition, where the effective learning rate is a product of base rate, arousal, circadian rhythm, reward prediction error, stability, inflammation suppression, and other biological factors.

---

## 6. Cognitive Module Integration

### 6.1 Global Workspace

Following Baars (1988) and Dehaene and Naccache (2001), the global workspace module implements a central broadcast architecture where modular processors compete for access to a limited-capacity workspace. The winning module's content is broadcast to all subscribers.

Key parameters: ignition threshold 0.6, capacity 256 floats, max 32 competitors/subscribers, 50ms refractory period (modeling the attentional blink).

### 6.2 Working Memory

Following Baddeley and Hitch (1974) and Miller (1956), working memory implements a limited-capacity buffer (default 7 items, max 20) with salience-based eviction and exponential temporal decay (tau = 1000ms). Items can be refreshed via attention (preventing decay). Emotional tagging boosts salience.

Inflammation from the immune system reduces capacity by 1-4 items, modeling the documented cognitive effects of neuroinflammation.

### 6.3 Theory of Mind

Following Premack and Woodruff (1978), the Theory of Mind module implements a Belief-Desire-Intention (BDI) model with 12 emotion categories. Key capabilities include behavioral observation, emotion inference, goal deduction, action prediction, empathy generation, and false belief detection.

### 6.4 Epistemic Filtering

The epistemic filtering module detects 12 cognitive biases and assesses evidence quality on a 7-level scale (NONE through CONSENSUS). This implements a form of epistemic hygiene where the system's own reasoning is subject to bias checking.

---

## 7. Training Pipeline

### 7.1 Five-Layer Architecture

The training pipeline implements five layers of control:

1. **Convergent training decisions**: Multi-module evidence accumulation using geometric mean composition for CONTINUE/PAUSE/ROLLBACK decisions
2. **Causal DAG**: 14-node directed acyclic graph modeling causal relationships between training dynamics (learning rate, batch size, gradient statistics, loss trajectory, biological state)
3. **Abductive failure diagnosis**: Threshold-based observation -> hypothesis generation -> corrective action
4. **Metacognitive strategy**: Per-domain EMA tracking with stall detection (delta < 0.001 for 5 windows) and mastery detection (accuracy > 0.85 for 5 windows)
5. **Unified continuous modulation**: Real-time adjustment of learning rate, batch size, and gradient clipping based on biological signals

### 7.2 Loss Functions

The system supports MSE, cross-entropy, binary cross-entropy, Huber, focal, KL divergence, triplet, and contrastive losses. All classification losses use epsilon clamping (1e-7) for numerical stability.

### 7.3 GPU Training Bridge

Training on GPU uses a weight cache architecture: sparse weights are extracted from the neuron array into dense GPU matrices for efficient GEMV operations. Gradient checkpointing reduces memory usage for deep networks.

---

## 8. Current Status and Limitations

### 8.1 What Works

- Brain creation, training, and inference through C and Python APIs
- GPU-accelerated forward and backward passes
- Multi-layer diamond architecture with automatic depth scaling
- FAST initialization mode (14 seconds for 1.5M neurons)
- Developmental training pipeline with 4-stage curriculum
- Immune system anomaly detection active during inference

### 8.2 What Doesn't (Yet)

- Training accuracy on benchmark datasets: 23-35% across 24 domains (target: 95%)
- Cross-modal integration between visual, auditory, and language pipelines is incomplete
- The ethics module has not been formally verified
- Scaling beyond single-GPU configurations is untested
- Performance benchmarks have not been independently validated

### 8.3 Honest Assessment

NIMCP is a research platform, not a production system. The safety properties described in this paper are architectural -- they exist in the code -- but whether they provide meaningful safety advantages over simpler approaches has not been empirically demonstrated. The training accuracy gap (23-35% vs. 95% target) means the system is not yet capable enough to test safety properties under realistic conditions.

---

## 9. Open Questions

1. **Does biological fidelity improve alignment, or just add complexity?** Biological brains are aligned to genetic fitness, not human values. The safety properties we implement are inspired by biological self-regulation, but the mapping from biological mechanism to AI safety property is not rigorous.

2. **Can developmental learning produce robust values?** Developmental staging might produce deeply integrated values (like human moral development) or brittle surface-level conditioning (like animal training). We lack tools to distinguish these outcomes.

3. **How do you verify architectural safety properties?** The ethics module sits in the decision pipeline, but formally verifying that it meaningfully constrains behavior requires techniques beyond what we have applied.

4. **Do properties hold at scale?** NIMCP currently operates at 1.5M neurons. Biological immune systems evolved for 86 billion neurons. We have no evidence our properties scale.

5. **What is the role of AI in AI safety research?** Much of NIMCP was developed with Claude's assistance, creating questions about the epistemological status of safety analyses produced by human-AI collaboration.

---

## 10. Conclusion

NIMCP represents an exploration of architectural approaches to AI safety. By implementing biological self-regulation mechanisms -- immune systems, homeostatic plasticity, developmental gating, ethical constraints -- as first-class architectural components, we create a platform for studying whether these properties provide meaningful safety advantages.

We make no claim to have solved alignment. We claim that the structural properties of brain-like architectures deserve investigation as complements to post-hoc alignment techniques, and that NIMCP provides a concrete platform for that investigation.

The system, its source code, and this paper are available at https://github.com/redmage123/nimcp.

---

## References

Amodei, D., Olah, C., Steinhardt, J., Christiano, P., Schulman, J., & Mane, D. (2016). Concrete problems in AI safety. *arXiv preprint arXiv:1606.06565*.

Baars, B. J. (1988). *A Cognitive Theory of Consciousness*. Cambridge University Press.

Baddeley, A. D., & Hitch, G. (1974). Working memory. In G. H. Bower (Ed.), *Psychology of Learning and Motivation* (Vol. 8, pp. 47-89). Academic Press.

Bi, G., & Poo, M. (1998). Synaptic modifications in cultured hippocampal neurons: Dependence on spike timing, synaptic strength, and postsynaptic cell type. *Journal of Neuroscience*, 18(24), 10464-10472.

Bienenstock, E. L., Cooper, L. N., & Munro, P. W. (1982). Theory for the development of neuron selectivity: Orientation specificity and binocular interaction in visual cortex. *Journal of Neuroscience*, 2(1), 32-48.

Buzsaki, G., & Draguhn, A. (2004). Neuronal oscillations in cortical networks. *Science*, 304(5679), 1926-1929.

Dehaene, S., & Naccache, L. (2001). Towards a cognitive neuroscience of consciousness: Basic evidence and a workspace framework. *Cognition*, 79(1-2), 1-37.

Destexhe, A., Mainen, Z. F., & Bhalla, U. S. (1994). Synthesis of models for excitable membranes, synaptic transmission and neuromodulation using a common kinetic formalism. *Journal of Computational Neuroscience*, 1(3), 195-230.

Friston, K. (2010). The free-energy principle: A unified brain theory? *Nature Reviews Neuroscience*, 11(2), 127-138.

Hasselmo, M. E. (2006). The role of acetylcholine in learning and memory. *Current Opinion in Neurobiology*, 16(6), 710-715.

Izhikevich, E. M. (2003). Simple model of spiking neurons. *IEEE Transactions on Neural Networks*, 14(6), 1569-1572.

LeCun, Y. (2022). A path towards autonomous machine intelligence. *openreview.net preprint*.

Maass, W., Natschlager, T., & Markram, H. (2002). Real-time computing without stable states: A new framework for neural computation based on perturbations. *Neural Computation*, 14(11), 2531-2560.

Miller, G. A. (1956). The magical number seven, plus or minus two: Some limits on our capacity for processing information. *Psychological Review*, 63(2), 81-97.

Pfister, J.-P., & Gerstner, W. (2006). Triplets of spikes in a model of spike timing-dependent plasticity. *Journal of Neuroscience*, 26(38), 9673-9682.

Premack, D., & Woodruff, G. (1978). Does the chimpanzee have a theory of mind? *Behavioral and Brain Sciences*, 1(4), 515-526.

Schultz, W., Dayan, P., & Montague, P. R. (1997). A neural substrate of prediction and reward. *Science*, 275(5306), 1593-1599.

Tononi, G. (2004). An information integration theory of consciousness. *BMC Neuroscience*, 5, 42.

Turrigiano, G. G. (2008). The self-tuning neuron: Synaptic scaling of excitatory synapses. *Cell*, 135(3), 422-435.

---

*All citations have been verified against their published sources. This paper was written by Braun Brelin with development and writing assistance from Claude (Anthropic).*
