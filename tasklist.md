# Task List — Feature & Enhancement Ideas

## DO NOT REINTRODUCE — removed by intent

The following layer types were intentionally removed because they
duplicated the forward pass of existing layers:

- `TNNetBias` — duplicate of `TNNetChannelBias` (forward pass).
- `TNNetLayerScale` (and its alias `TNNetLearnableScale`) — duplicate of
  `TNNetChannelMul` (forward pass).
- `TNNetNeg` — duplicate of `TNNetNegate` (which is itself just
  `TNNetMulByConstant.Create(-1)`). Use `TNNetNegate` for `y = -x`.
- `TNNetGlobalAvgPool` — empty-body subclass of `TNNetAvgChannel`. Use
  `TNNetAvgChannel` for global average pooling.
- `TNNetGlobalMaxPool` — overlapped `TNNetMaxChannel`. Use
  `TNNetMaxChannel` for global max pooling. Note: `TNNetMaxChannel`
  currently assumes square feature maps (`SizeX == SizeY`); the deleted
  `TNNetGlobalMaxPool` had a direct (X, Y) loop that also worked on
  rectangular inputs. If you ever need global max on a non-square
  tensor, fix `TNNetMaxChannel` rather than reintroducing this class.
- `TNNetGlobalMinPool` — overlapped `TNNetMinChannel`. Use
  `TNNetMinChannel` for global min pooling. Same square-only caveat as
  `TNNetMaxChannel` above.
- `TNNetThresholdedReLU` — strict subset of `TNNetThreshold`.
  `ThresholdedReLU(x; θ)` is `TNNetThreshold.Create(theta=θ, value=0)`.
  Use `TNNetThreshold` directly.

Do NOT add them back under any name. The minor differences they had
(true-sum vs spatial-mean weight-gradient scaling; constructor-
configurable initial scale) are not worth the code duplication. If a
true-sum gradient or a configurable initial multiplier is genuinely
needed, extend `TNNetChannelBias` / `TNNetChannelMul` with an option
flag instead of forking a new layer class. Any task entry below that
references these removed layers is obsolete and should be ignored
rather than acted on.

## New layer types
<!-- (Sparse / mixture-of-experts routing layer removed: duplicate of the
     concrete TNNetMixtureOfExperts entry under "Probability projections /
     sparsity".) -->
<!-- (Two TNNetFourierFeatures spectral-bias follow-ups removed: completed,
     landed in examples/FourierFeaturesSpectralBias/.) -->

## Interesting applications / examples
- [ ] Reinforcement learning: minimal DQN solving CartPole or a grid world
- [ ] Style transfer or diffusion-lite denoiser (building on SuperResolution / VisualGAN)

## Infrastructure / dev experience
- [ ] Mixed-precision (FP16) volumes for the OpenCL path
- [ ] Gradient checkpointing for training deeper nets in less memory
- [ ] Model zoo loader that pulls pre-trained weights from the companion repo
- [ ] ONNX import
- [ ] ONNX (or simpler JSON) export path — minimal viable: dump a
      forward-only graph for the currently-supported subset of layers,
      enough to run inference in onnxruntime. Doc which layers are
      out-of-scope for v1.
- [ ] CI-friendly headless test runner with coverage reporting
- [ ] Expand layer test coverage — numerical-gradient checks for layers that lack them

## Documentation / learning
- [ ] Interactive "build your first transformer in Pascal" tutorial
- [ ] Auto-generated layer API reference from doc comments
- [ ] Improve source-code comments for TNNetChannelShuffle and
      TNNetInterleaveChannels in neural/neuralnetwork.pas. Both are
      parameter-free channel-permutation layers and are easily confused.
      The doc comments should make the distinction explicit: spell out
      the permutation formula each one computes, the meaning of the
      constructor parameter (Groups vs StepSize), any constraints
      (ChannelShuffle requires Depth mod Groups = 0; InterleaveChannels
      has no divisibility constraint), and a one-line note on the
      typical use case (ShuffleNet-style group mixing vs generic
      stride-based interleaving after grouped/parallel convs).

## Added ideas

### Smaller follow-up ideas
- [ ] Multi-threaded determinism investigation: SeededReproducibility passes
      with `MaxThreadNum := 1` but no test pins what breaks at `>1`. Add a
      sibling demo (or extend it) that runs with `MaxThreadNum := 4` twice
      and prints which weights diverge first — useful starting point for any
      future "make TNeuralFit deterministic under parallelism" work.
- [ ] CumSumPositionEncoding follow-up: actually train a tiny position-
      dependent model with and without the CumSum feature concatenated and
      chart loss delta. Forward-only demo landed; the bake-off is still open.
- [ ] Quick-start example: tiny char-level sequence model (XOR-of-bits or
      counting task) that trains in well under a minute on CPU.
<!-- (Volume unit micro-benchmark removed: duplicate of the `bin/layer_bench`
     CLI under "Tooling / dev experience", whose own entry notes it "subsumes
     the long-pinned Volume micro-benchmark and extends it to layers".) -->
#### Experiments I'm curious about
- [ ] Weight-initialization sensitivity demo: show how a deep-ish net's
      first-epoch gradient magnitudes change across the available init schemes.
#### Documentation
<!-- ("How numerical gradient testing works in this repo" contributor note
     removed: duplicate of the docs/numerical_gradient.md tutorial entry under
     "Documentation I'd enjoy writing".) -->
- [ ] Write a one-page "layer authoring checklist" — constructor + LoadFromString
      round-trip, CreateLayer dispatch entry, Compute/Backpropagate, and the
      mandatory numerical-gradient test. Captures the recurring steps every
      new-layer task in this file actually follows.
- [ ] "Reading a numerical-gradient failure" mini-guide — when the harness
      reports a mismatch, what does the magnitude tell you (analytic-bug
      vs. tolerance-too-tight vs. discontinuity-near-the-eps-step)?
- [ ] "Picking a tolerance" mini-guide for numerical-gradient tests — when
      1e-2 is fine, when to tighten to 1e-3, when to shrink eps instead of
      loosening the tolerance.

#### Experiments I'm curious about
- [ ] Batch-size sweep demo: same net and data, vary the batch size, and print
      how wall-clock-per-epoch and epochs-to-converge trade off. A concrete,
      visible illustration of a tuning knob beginners always ask about.

### Added ideas
- [ ] TNNetMaskedFill currently hard-codes the upper-triangle (strictly causal)
      pattern. Consider a follow-up that allows masking the lower triangle or a
      configurable offset, if a non-causal masking use case shows up.

### Ideas from JP
- [ ] Better integrate TBytePredictionViaNNet and TEasyBytePredictionViaNNet with
      TNNet. Find a way to backpropagate. May open a new class of problem solving.
      This is very interesting.
- [ ] Use TBytePredictionViaNNet and TEasyBytePredictionViaNNet as inspiration for
      new float32 based layers. This is also curious and interesting.
- [ ] Integrate with float32 functions from https://github.com/joaopauloschuler/pas-core-math
      for faster and more precise math.
- [ ] More image generative examples and or experiments.

### TNNetMultiHeadSelfAttention — breakdown
SDPA + RoPE + MaskedFill + ALiBi are all in tree. Suggested commit-sized
breakdown:
- [ ] (MHA-a) Add a small `TNNetSplitChannels`-based helper or example that
      carves a (3*d_model) Q|K|V depth slab into H per-head (3*d_k) slices,
      with a sanity test on H=2, d_model=8.
- [ ] (MHA-b) Add a wiring helper or example that runs one
      `TNNetScaledDotProductAttention(d_k)` per head slice and concats
      the H outputs via `TNNetDeepConcat` back to depth d_model. Test on
      a tiny (H=2, d_k=4, SeqLen=3) shape, numerical-gradient through.
- [ ] (MHA-c) Wrap (a)+(b)+a `TNNetFullConnectLinear(d_model)` out-projection
      into a `TNNetMultiHeadSelfAttention` helper class or builder function.
      Add a numerical-gradient test on the same tiny shape.
- [ ] TNNetTransformerEncoderBlock helper — LayerNorm → MHA → residual →
      LayerNorm → SwiGLU FFN → residual. Single call, configurable
      d_model / heads / d_ff. Companion numerical-gradient test on a tiny
      shape (d_model=8, heads=2, seq=3). Pre-norm and post-norm variants
      behind a flag.
- [ ] TNNetTransformerDecoderBlock helper — adds the causal MaskedFill in
      front of self-attention and an optional cross-attention sub-block.
      Built on top of the encoder helper above to avoid duplication.
- [ ] TNNetCrossAttention — same SDPA core but with separate Q vs K|V
      input branches (so encoder-decoder is reachable). Forward +
      gradient-check on a tiny shape.

### Attention variants / siblings
- [ ] TNNetDifferentialAttention follow-up: the paper's headline
      NOISE-CANCELLATION micro-experiment (deferred at landing — only the four
      correctness tests shipped). On a tiny causal next-token task with an
      "all-keys-irrelevant" probe row, compare plain SDPA vs
      TNNetDifferentialAttention and print the attention-noise mass on the
      irrelevant keys — the differential output should land strictly below
      plain SDPA's. ~30-line wiring swap, mirrors the open SinkAttention
      stability micro-experiment; all pieces now in tree.
- [ ] TNNetDifferentialAttention follow-up: fold differential heads into the
      MHA breakdown ([[TNNetMultiHeadSelfAttention]] /
      TNNetTransformerDecoderBlock) behind a flag, so a decoder block can opt
      into differential attention per head — a natural drop-in for the
      downstream ../gpt-3-for-pascal long-context retrieval.
- [ ] TNNetSinkAttention follow-up (now landed): attention-sink stability
      micro-experiment. On a tiny causal next-token task with an "all-keys-
      irrelevant" probe row, compare plain SDPA vs TNNetSinkAttention and
      print the attention mass that lands on the sink slot(s) vs real keys —
      the StreamingLLM claim is the sink absorbs the otherwise-misplaced mass.
      Sweep K ∈ {1, 2, 4}. ~30-line wiring swap; all pieces in tree.
- [ ] TNNetSinkAttention follow-up: fold sink slots into the MHA breakdown
      ([[TNNetMultiHeadSelfAttention]] / TNNetTransformerDecoderBlock) so a
      decoder block can opt into sinks per head behind a flag.
- [ ] TNNetTalkingHeadsProjection — pre/post-softmax linear mix across
      heads (Shazeer et al.). A tiny learnable HxH multiply applied to
      attention logits along the head axis.
- [ ] TNNetCosineSimilarityAttention follow-up: bake-off vs plain SDPA and vs
      SDPA+TNNetSoftCapping on a tiny next-token task — does the bounded
      `[-scale,+scale]` logit actually remove the NaN/overflow events SoftCapping
      targets, at matched final loss? All three pieces are now in tree.
- [ ] TNNetCosineSimilarityAttention follow-up: make `scale` a learnable scalar
      (sibling to ReZero's single-weight pattern) instead of a fixed FFloatSt[0]
      constant, and check whether training drives it toward the cargo-culted
      `1/τ` temperatures used in cosine-attention papers.
- [ ] SDPA all-masked-row policy decision and test: currently a row where
      every key is masked produces NaN (softmax of all -inf). Concrete
      proposal: detect the all-masked row in Compute, output a zero row,
      skip the softmax for that row (what JAX/Flax MHA does). Document
      the choice in code and add the pinning test.
- [ ] "Attention numerical-gradient stress test" running the SDPA grad check
      across SeqLen ∈ {1, 2, 3, 5, 8} and asserting the max error vs
      tolerance at each. Pins shape-edge behavior the existing single-shape
      test can't see.
<!-- (Inline shape-annotation comments on TNNetScaledDotProductAttention
     Compute/Backpropagate removed: duplicate of the "Inline-comment cleanup
     pass on TNNetScaledDotProductAttention" entry under "Documentation I'd
     enjoy writing".) -->

### Bake-off / experiment follow-ups
<!-- (Position-encoding bake-off removed: completed, landed in
     examples/PositionEncodingBakeoff/.) -->
- [ ] Position-encoding bake-off follow-up: the landed bake-off uses a
      predict-the-PREVIOUS-token task on which ALiBi lands just above the
      no-position baseline — a single head's `2^-8` slope is a weak recency
      bias that under the causal mask favours the query's own position and
      injects NO positional content into the values, so it cannot do
      fixed-offset (-1) retrieval. Add an ALiBi-FAVOURABLE second task
      (a long-context recency / "attend-to-the-nearest-recent-match" task)
      and/or a multi-head variant with per-head slopes `2^(-8h/H)`, so the
      arm where ALiBi's locality prior actually wins is also demonstrated.
      Pairs with the open "ALiBi slope-base sweep" entry.
- [ ] Causal-mask sanity experiment: train a tiny attention model on
      next-token prediction WITH and WITHOUT TNNetMaskedFill, and show
      the unmasked one cheats (near-zero loss but useless at generation).
- [ ] Numerical-precision study: re-run the activation bake-off using FP32
      vs a simulated-FP16 path (round-trip volumes through fewer mantissa
      bits) and report the convergence-quality gap. Useful baseline for
      any future mixed-precision work.
- [ ] SoftCapping logit-stability micro-experiment: train a tiny classifier
      with and without a `TNNetSoftCapping(c)` before the final softmax,
      and print the rate of NaN/overflow events under an aggressive LR.
- [ ] DropPath ablation: train a small ResNet-style net on a tiny synthetic
      task with `TNNetDropPath(p)` after each residual block, sweeping
      `p ∈ {0.0, 0.1, 0.2}` and printing final loss.
- [ ] DropPath schedule study: linearly increasing drop probability with
      depth (Stochastic-Depth schedule) vs constant `p`.
- [ ] RoPE base-frequency sweep: same tiny next-token model, sweep
      `base ∈ {1e2, 1e3, 1e4, 1e5}`, chart loss and qualitative sample
      quality.
- [ ] ALiBi slope-base sweep: vary slope from `2^(-8h/H)` to `2^(-kh/H)` for
      `k ∈ {4, 6, 8, 12}` on a tiny next-token task and chart loss.
      Empirical check of the cargo-culted "8" constant.
- [ ] Causal-mask + SoftCapping interaction study: with logits clipped via
      `TNNetSoftCapping(c)`, sweep `c ∈ {5, 10, 20, 30, ∞}` on a tiny
      next-token task and chart loss + max-logit-norm.
- [ ] "Lottery-ticket"-flavored experiment: train a small dense net,
      magnitude-prune the bottom X% of weights, retrain from the original
      init, and compare. Pure CPU, finishes in seconds.
- [ ] Init-scheme × depth heatmap: for depths {2, 4, 8, 16} and inits
      {Glorot, He, LeCun, plain N(0, 0.01)}, plot first-step gradient norm
      at the deepest layer.
- [ ] "Which init wins per activation" matrix: cross-product of init schemes
      × activation functions on a fixed tiny MLP, report epochs-to-converge.
- [ ] First-batch gradient-norm heatmap across (depth, width, init):
      enumerate a small grid, print one number per cell.
- [ ] Train-time vs inference-time delta sweep for the noise layers
      (TNNetDropout, TNNetDropPath, TNNetSpatialDropout1D/2D): same tiny
      classifier, sweep `p ∈ {0.0, 0.1, 0.2, 0.4}`, chart train vs val loss.
- [ ] Numerical-gradient eps sweep: pick one well-tested layer, run the
      gradient check with `eps ∈ {1e-2, 1e-3, 1e-4, 1e-5, 1e-6}` and print
      max-error vs eps.

### Composite blocks / builders I'd enjoy shipping
<!-- (PreNorm / RMSNorm / PostNorm residual builders removed: completed,
     landed as TNNet.AddPreNormResidual / AddRMSNormResidual /
     AddPostNormResidual.) -->
- [ ] TNNetAffineBlock — once TNNetMul lands, `Mul → Bias` builder for a
      learnable per-channel affine transform separable from FullConnect.

#### Attention / sequence
- [ ] TNNetCausalConv1D — 1D conv with left-only padding so output at
      position t depends only on positions ≤ t. Backward is the standard
      conv backward minus the masked-future part. Pairs with TNNetTokenShift
      and unblocks attention-free baseline experiments. (Already possible with existing layers?)
- [ ] KV-cache incremental-decode path for TNNetScaledDotProductAttention —
      the single biggest efficiency gap for autoregressive generation with
      the downstream ../gpt-3-for-pascal model. Today, sampling the next
      token re-encodes the entire prefix every step, so generating N tokens
      costs O(N^2) attention work. Add an inference-only mode that, given a
      one-token query at position t, appends its K and V to a persistent
      per-layer cache and attends over the cached keys/values [0..t] instead
      of recomputing them — turning per-step cost from O(t) to O(1) in the
      prefix length. Scope notes: (a) cache lives on the SDPA layer, gated by
      an explicit BeginIncrementalDecode / EndIncrementalDecode (or a
      FCacheEnabled flag) so the training forward/backward path is untouched
      and bit-for-bit unchanged — the cache only activates for single-token
      forward passes at inference; (b) RoPE/ALiBi position offsets must be
      driven by the running cache length, not the (now length-1) input
      SizeX, so positional encoding stays correct mid-stream; (c) provide a
      ResetCache for starting a fresh sequence and document the max-context
      preallocation. Headline correctness test, and a tiny
      examples/IncrementalDecode/ demo: feed a SeqLen sequence two ways —
      one full re-encode, and one token-at-a-time through the cached path —
      and assert the final-position logits match to < 1e-5 (the built-in
      faithfulness check), then print measured per-token wall-clock vs prefix
      length to show the O(t)->O(1) flattening. Builds on the existing
      AttentionWeights accessor and the MHA breakdown above
      ([[TNNetMultiHeadSelfAttention]] / TNNetTransformerDecoderBlock); a
      genuinely new capability, not a re-skin of an existing layer.
- [ ] TNNetDiagonalSSM follow-up: add it as the fourth contender in the
      open "causal-conv vs token-shift vs SDPA on the same toy next-token
      task" experiment — its selling point is matching attention quality
      at linear cost.
- [ ] KV-cache / incremental-decode O(1)-per-step path for
      TNNetDiagonalSSM (a linear recurrence is O(1)-per-step by nature;
      the SDPA incremental-decode notes above apply doubly here).
- [ ] TNNetTokenHistoryPenalty follow-up: wire it into the downstream
      ../gpt-3-for-pascal generation loop (call `Apply` before the sampler
      and `RegisterToken` after each emit, `ResetHistory` per sequence) and
      show a qualitative before/after on a repetition-prone prompt — the
      class landed this lucky-day batch (neuralvolume.pas, 7 tests in
      tests/TestNeuralSamplers.pas) but no in-tree generator calls it yet.
- [X] TNNetGatedResidual follow-up: a residual builder
      `TNNet.AddGatedResidual(pSublayers)` wiring
      `y = x + GatedResidual(Sublayer(x))`. LANDED (2026-05-24 lucky-day
      batch) as a sibling to AddPreNormResidual/AddRMSNormResidual/
      AddPostNormResidual (no normalization; the per-channel gate inits to 0
      so the branch starts as identity). Ships forward-wiring (exact
      identity-at-init + x+alpha*Sublayer(x)) and end-to-end input
      numerical-gradient tests.
- [ ] TNNetGatedResidual follow-up: ReZero-vs-GatedResidual depth ablation —
      train a deepish residual MLP with scalar ReZero vs per-channel
      GatedResidual gates, chart whether the per-channel gate opens unevenly
      across channels. NOW EASIER: AddGatedResidual landed, so this is a
      builder swap against a ReZero-wired arm (mirror the structure of
      examples/PreNormVsPostNorm/, which already wires a deepish residual
      stack via the residual builders).
- [ ] TNNetReversibleBlock — RevNet-style additive coupling
      (`y1 = x1 + F(x2)`, `y2 = x2 + G(y1)`). Forward + inverse round-trip
      to within fp tolerance is the headline test.
- [ ] TNNetWeightStandardization follow-up: a CONVOLUTION variant
      (standardize a conv layer's filters per output channel). The dense
      form landed; the conv form is the headline WS use case (Qiao et al.
      pair it with GroupNorm in a conv stack). Mirror the dense Jacobian
      per output-channel filter. Pairs with a tiny WS+GroupNorm vs
      BatchNorm CIFAR-stub bake-off.
- [ ] TNNetSpectralNorm wrapper — wraps an existing FullConnect or
      Convolution layer and divides its weight matrix by its largest
      singular value (one power-iteration step per forward pass).
      NOTE: the reusable power-iteration helper `TNNet.EstimateSpectralNorm`
      now exists (landed with WeightSpectrumReport) — build the wrapper on
      top of it rather than re-deriving the iteration.
- [ ] TNNetStochasticPool — sample one cell per pooling window weighted by
      its activation (softmax of activations over the window) at training,
      take the expectation at inference.
- [ ] TNNetShakeShake / TNNetShakeDrop — Shake-Shake regularization and
      its single-branch ShakeDrop generalization.

#### Channel attention / conditioning
- [ ] TNNetCBAM — SE block plus a spatial-attention sibling.
- [ ] TNNetFiLM (Feature-wise Linear Modulation) — `y = gamma * x + beta`
      with gamma/beta from a separate conditioning input branch.
- [ ] TNNetMaxBlurPool — anti-aliased max-pool: max-pool followed by a
      fixed (non-trainable) binomial blur filter.

#### Activations (gradient-checkable, mostly TNNetReLUBase descendants)
<!-- (TNNetMishExact / TNNetMish-stable removed: the in-tree TNNetMish ALREADY
     implements the stable formulation — its Compute() branches on x>20
     (softplus≈x) and x<-20 (softplus≈exp(x)≈0) to avoid the exp overflow.
     A separate "stable Mish" class would be a forward-pass duplicate of
     TNNetMish, which the "DO NOT REINTRODUCE" policy at the top of this file
     forbids. Verified 2026-05-24 lucky-day batch.) -->
- [ ] TNNetSplineActivation follow-up: a KAN-vs-MLP toy-fit micro-experiment.
      Fit a wiggly 1D target (e.g. `y = sin(3x) + 0.3·sin(11x)`) with a small
      MLP whose ReLUs are swapped for TNNetSplineActivation at matched param
      count, and chart final loss + the learned per-channel spline shapes
      (dump `(x, y)` over [-Range,+Range]). ~30-line activation swap; the
      headline KAN claim is that the learnable activation buys lower loss at a
      fixed width. Pairs with the open TNNetAPL bake-off.
- [ ] TNNetSplineActivation follow-up: knot-count / Range sweep — same toy fit
      with K ∈ {2, 4, 8, 16} and a couple of Range values, charting the
      capacity↔overfitting trade and where extra knots stop helping.
- [ ] TNNetMetaAconC follow-up: the FULL cross-channel-bottleneck β generator
      (the paper's true Meta-ACON: squeeze → FC channel-reduce → ReLU → FC
      channel-expand → sigmoid, so β[c] depends on ALL channels' spatial
      means, not just channel c's). The landed TNNetMetaAconC uses a per-channel
      affine-over-squeeze simplification; this variant needs a small two-FC
      sub-block inside the layer (or a builder that wires an SE-style squeeze
      into the β path) and is NOT a per-channel-transform shape, so scope it as
      its own layer/builder rather than a ChannelTransformBase descendant.
- [ ] TNNetBitLinear follow-up: a ternary-vs-full-precision bake-off — train the
      same tiny classifier with `TNNetFullConnectLinear` heads vs `TNNetBitLinear`
      heads at matched architecture, report final accuracy/loss AND the effective
      model size (ternary weights are ~1.58 bits each vs 32). The headline BitNet
      claim is "near-FP accuracy at a fraction of the weight memory"; this is a
      ~30-line head swap. Pairs with the STE bit-width sweep and the
      TNNetStraightThroughEstimator quantization demos already in the list.
- [ ] TNNetBitLinear follow-up: activation-quantization variant — BitNet b1.58
      also quantizes the *activations* to int8 (absmax per-token). Consider a flag
      or sibling that rounds the layer INPUT through an absmax STE before the
      ternary matmul, so the "fully-quantized linear" path is reachable. Scope as
      its own flag on TNNetBitLinear (forward adds an input absmax-round; backward
      STE-passes the input gradient unchanged).
<!-- (TNNetMaxOut2 removed: a "two-piece special case of TNNetMaxOut" is just
     TNNetMaxOut.Create(2) with a thinner constructor — i.e. a forward-pass
     duplicate of the existing TNNetMaxOut, which the "DO NOT REINTRODUCE"
     policy at the top of this file forbids. If a no-group-count convenience
     constructor is genuinely wanted, add an overload to TNNetMaxOut instead of
     a new class. Flagged 2026-05-24 lucky-day batch.) -->
- [ ] TNNetAPL follow-up: APL-vs-PReLU-vs-ReLU bake-off on the hypotenuse toy
      (or a tiny CIFAR stub) at matched param count, sweeping the hinge count
      S ∈ {1, 2, 4} — does the extra piecewise capacity buy lower final loss?
      The activation has landed, so this is a ~30-line activation swap.
#### Probability projections / sparsity
- [ ] TNNetGumbelSoftmax follow-up (now landed): temperature-annealing
      micro-experiment — train a tiny discrete-latent autoencoder whose
      bottleneck is a `TNNetGumbelSoftmax`, anneal `tau` from ~2.0 down to
      ~0.1 over training, and chart reconstruction loss vs `tau` plus the
      bottleneck's output entropy (the categorical sharpens as tau drops).
      The layer + its soft/hard modes are in tree; this is the headline
      use case. Pairs with the open TNNetMixtureOfExperts routing gate.
- [ ] TNNetMixtureOfExperts — top-k softmax gate over N expert sub-networks
      plus a load-balancing auxiliary loss. (The just-landed
      TNNetGumbelSoftmax is the natural differentiable hard-routing gate.)

#### Normalization primitives
- [ ] TNNetMinMaxNorm follow-up: a per-channel variant (min/max reduced over
      spatial only, independently per depth channel) gated by a flag, mirroring
      the per-(x,y)-over-depth vs full-volume split discussed for L2Normalize.
      Builds on the landed full-volume TNNetMinMaxNorm.
- [ ] TNNetUnitNormConstraint — projection layer that L2-normalizes the
      *weights* of the previous trainable layer after each step.

#### Reduction / shape
- [ ] TNNetAdaptiveAvgPool example/usage: swap a fixed global-avg head
      (`TNNetAvgChannel`) for `TNNetAdaptiveAvgPool.Create(1)` in one
      SimpleImage path, or a tiny demo showing the same conv stack accepting
      two different input resolutions and producing a fixed-size head.
- [ ] TNNetGather — single-channel index-into-a-channel layer.
- [ ] TNNetUpsampleNearest backward consistency: assert summing the
      per-block output errors equals the input error.
- [ ] Pooling bake-off example `examples/PoolingBakeoff/`: same tiny conv
      classifier, swap the pooling head across `TNNetAvgPool` / `TNNetMaxPool`
      / `TNNetLpPool` (sweep `p ∈ {1, 2, 4, 8}`) / `TNNetSoftPool`, chart final
      loss/accuracy on a small CIFAR stub. Visualises the average<->max
      interpolation empirically. All four pooling layers are in tree.
      NOW UNBLOCKED to also sweep `TNNetSoftPool` `beta ∈ {0.5, 1, 2, 8}`
      (landed this lucky-day batch) as a fifth column — the SoftPool beta
      knob spans the same average↔max family as LpPool's `p`, so the two
      sweeps can be charted side by side.
- [ ] TNNetAdaptiveMaxPool example/usage: a tiny demo showing the same conv
      stack accepting two different input resolutions and producing a
      fixed-size head via `TNNetAdaptiveMaxPool.Create(1)` (global-max head),
      sibling to the open TNNetAdaptiveAvgPool example task above. Layer +
      gradient/forward tests already landed.
### Loss layers
- [ ] TNNetCosineEmbeddingLoss follow-up (now landed): a tiny
      siamese-pair embedding micro-example — train two shared-weight MLP
      branches whose outputs are concatenated into the `a|b|y` layout, on a
      synthetic "same vs different class" pair task, and print the learned
      same-pair vs different-pair cosine histograms. Headline use case for
      the landed head; pairs with [[TripletEmbedding]].
- [ ] TNNetKLDivergence distillation follow-up (now landed
      examples/KnowledgeDistillation/): temperature sweep T in {1,2,4,8} on this
      example — chart how soft-target sharpness changes the distilled student's
      accuracy/agreement.
- [ ] Tversky α/β asymmetry sweep on the segmentation micro-example: with a
      deliberately class-imbalanced mask, sweep `(α,β) ∈ {(0.5,0.5),(0.3,0.7),
      (0.7,0.3)}` and show how β>α trades precision for recall (fewer false
      negatives). Pure α/β knob study on the landed TNNetTverskyLoss.
      NOW UNBLOCKED: fork examples/DiceSegmentation/ (landed above) and swap the
      head for TNNetTverskyLoss with the three (α,β) pairs.
- [ ] LabelSmoothing calibration check: train SimpleImageClassifier with
      `TNNetLabelSmoothingLoss(eps)` at `eps ∈ {0, 0.05, 0.1, 0.2}` and feed
      each into the `neuralcalibration` ECE/Brier report — the textbook claim
      is smoothing improves calibration at a small accuracy cost. Both pieces
      (the loss and the calibration report) have landed.
- [ ] TNNetContrastiveLoss / InfoNCE — input split into query/key, computes
      InfoNCE against other samples in the minibatch.
- [ ] TNNetCenterLoss — joint softmax + `λ·||x - c_y||²` with EMA-updated
      class centers stored as the layer's weight tensor.
- [ ] TNNetArcFace — additive angular-margin softmax for face/embedding
      recognition heads.
- [ ] TNNetVectorQuantizer (VQ-VAE bottleneck) — codebook of K vectors with
      straight-through assignment plus commitment/codebook losses.

### Training infrastructure (the "missing plumbing")
- [ ] TNeuralLRScheduler interface (`function NextLR(Epoch, Step): TNeuralFloat;`)
      with concrete implementations: TStepLR, TCosineAnnealingLR
      (η_min + (η_max-η_min)·0.5·(1+cos(π·t/T))), TWarmupCosineLR (linear
      warmup then cosine), and PolyLR (`η · (1 - t/T)^p`).
- [ ] StochasticWeightAveraging helper — TNNet wrapper maintaining a running
      average of live weights every N steps after epoch W.
- [ ] TNNetEMAWrapper / SetEmaShadow — exponential moving average of network
      weights for inference, sibling to SWA.
- [ ] Lookahead optimizer wrapper — every k inner SGD steps, set slow weights
      `φ ← φ + α·(θ - φ)` and rewind fast weights to φ.
- [ ] GradientClipping options on TNeuralFit — both `clip_norm` (global)
      and `clip_value` (element-wise).
- [ ] Layerwise learning-rate multipliers — per-layer `LRMult` field that
      the optimizer respects. Unlocks discriminative fine-tuning.
- [ ] NaN/Inf guard hook for TNeuralFit — optional "abort training and
      print the offending layer" check after each forward+backward pass.
      Plus a regression test that deliberately seeds a NaN and confirms
      the assertion fires at the right layer.
- [ ] Mixup data augmentation helper.
- [ ] Sharpness-Aware Minimization (SAM) experiment `examples/SharpnessAwareMinimization/`
      (Foret et al. 2021) — the one well-known optimizer idea NOT covered by the
      SWA / EMA / Lookahead / gradient-clipping plumbing above, and a natural
      partner to the landed [[LossLandscapeProbe]] (which already prints a
      sharpness scalar + loss-doubling radius). SAM is a two-pass step: from the
      current weights `w`, do (1) a forward+backward to get `g = dL/dw`, (2)
      climb to the worst-case neighbour `w_adv = w + rho * g/||g||` (the
      "ascent" step, a whole-net snapshot + perturb), (3) a SECOND
      forward+backward AT `w_adv` to get the perturbed gradient, then (4) restore
      `w` and apply that perturbed gradient with the normal optimizer — so the
      step minimises the loss of the worst point in a rho-ball, biasing training
      toward FLAT minima. Scope it as a SELF-CONTAINED example with a hand-rolled
      mini-batch loop (like SineRegression / BinaryAdder already do — no intrusive
      TNeuralFit surgery), reusing the existing whole-net `SaveDataToString` /
      `LoadDataFromString` snapshot for the restore (the same trick
      LayerSensitivityReport uses) and the per-parameter gradient tensors
      `Backpropagate` already populates for the `||g||` norm and the perturb. Train
      the SAME tiny MLP twice on a small noisy-label classification toy — plain SGD
      vs SAM at matched LR/epochs — and report: final train/val loss + accuracy,
      and the headline FLATNESS contrast by calling `TNNet.LossLandscapeProbe` on
      both trained nets (SAM's sharpness scalar and loss-doubling radius should
      land flatter/wider — the built-in correctness signal that SAM did what it
      claims). Sweep `rho in {0.0, 0.01, 0.05, 0.1, 0.2}` (rho=0 must reproduce
      plain SGD bit-for-bit — a second built-in invariant) and chart the
      sharpness-vs-rho and val-accuracy-vs-rho curves. Distinct from everything in
      tree: LossLandscapeProbe only MEASURES sharpness on a frozen net, the
      AdversarialRobustness report perturbs the INPUT (not the weights) and never
      steps, and SWA/EMA average weights post-hoc rather than changing the
      gradient that is applied. Pure CPU, no external data, fits a few-minute
      budget. Pairs with the open weight-decay / generalization experiments
      ([[WeightSpectrumReport]]).
### Introspection / debugging tools
- [X] TNNet.ToGraphvizDot — emit a `.dot` file describing the layer DAG.
      LANDED (2026-05-24 lucky-day batch): instance method returning a
      `digraph` string (node per layer with index/class/output-shape,
      edges from the real DAG incl. multi-input TNNetConcatBase layers via
      the same FPrevLayerList SaveStructureToString uses). Ships
      examples/GraphvizExport/ + TestToGraphvizDotSmoke. Follow-up still
      open: the sibling WriteLayerTimings(NN, Sample) below.
- [ ] WriteLayerTimings(NN, Sample) — runs one forward pass and prints
      per-layer wall-clock to stdout.
- [ ] ActivationStatsReport follow-up: the per-layer `|median|` is currently
      approximated from the last probe sample only (streaming moments keep
      memory bounded). Add an exact per-layer median across the whole probe
      batch via a two-pass or bounded reservoir approach if it proves worth
      the memory; the single-sample approximation is documented in the doc
      comment for now.
- [ ] WeightSpectrumReport follow-up: a probe-batch `JacobianSpectrumReport`
      variant that estimates the top singular value of each layer's
      input-output Jacobian (the entry already flags this as the natural
      next knob). Reuses the landed `TNNet.EstimateSpectralNorm` power-
      iteration helper.
- [ ] GradientConflictReport follow-up: the raw `cos<0` conflict fraction is
      dominated by a softmax head's mildly-anti-correlated cross-class pairs, so
      the report falls back on a `cos<-0.5` strong-conflict tail. Add a sibling
      run (or example variant) with a raw-logit `TNNetFullConnectLinear` head and
      document whether the plain `cos<0` fraction becomes discriminating there —
      the same raw-logit-vs-softmax-head question MarginReport's follow-up raises.
- [ ] GradientConflictReport follow-up: the per-class-pair mean-cosine matrix is
      the natural precursor to gradient-surgery / PCGrad — add an experiment that
      reweights or projects out the most-conflicting class pair's gradient and
      charts the batch-loss delta.
- [ ] EffectiveReceptiveFieldReport follow-up: add the optional `(radius, mass-
      fraction)` CSV side-output so the cumulative-mass curve can be plotted
      outside the terminal (~10 lines, mirrors the CSV side-output in
      DecisionBoundaryReport / the AdversarialRobustnessReport CSV follow-up).
- [ ] EffectiveReceptiveFieldReport follow-up: sweep dilation / kernel size on
      the stem and chart effective-RF growth vs theoretical-RF growth — the
      headline Luo et al. 2016 "effective RF grows sub-linearly" curve.
- [ ] `TNNet.NeuralTangentKernelReport(NN, Samples)` — the empirical
      Neural-Tangent-Kernel diagnostic (Jacot et al. 2018), the gradient-space
      object that actually governs gradient-descent training dynamics. On a
      FROZEN net (`ClearDeltas` per sample, never `UpdateWeights`) it snapshots
      each sample's full flattened per-parameter weight-gradient vector `g_i` of
      the scalar target-class logit — REUSING the exact per-sample gradient
      machinery `FisherImportanceReport` / `GradientConflictReport` /
      `GradientNoiseScaleReport` already share (no input-gradient enablement) —
      and forms the empirical NTK Gram matrix `K_ij = <g_i, g_j>` over the probe
      batch. It then reports: the kernel as a glyph-shaded ASCII heatmap; its
      FULL eigenspectrum via the SAME self-contained Double-precision cyclic
      Jacobi eigensolver `WeightSpectralTailReport` already ships (so no new
      numerical code); the condition number `lambda_max/lambda_min` (a predictor
      of convergence speed — ill-conditioned NTK ⇒ slow training); the
      **kernel-target alignment** `<K, yy^T>_F / (||K||_F ||yy^T||_F)`
      (Cristianini et al. 2001 — high alignment predicts good generalization,
      the headline NTK-theory number); the effective rank / participation ratio
      `(sum lambda)^2 / sum lambda^2`; a `log10(lambda)` histogram; and an
      optional fresh-init-vs-trained contrast quantifying NTK DRIFT (≈0 drift =
      the infinite-width "lazy/kernel" regime; large drift = "rich"
      feature-learning — the lazy-vs-rich question made visible). Built-in
      correctness checks: symmetry `K_ij == K_ji`, PSD (all Jacobi eigenvalues
      `>= 0` since `K = G G^T`), and the diagonal `K_ii == ||g_i||^2 > 0`.
      DISTINCT from `GradientConflictReport` (which reports normalised pairwise
      gradient COSINES + a conflict fraction — sign geometry, not the
      un-normalised kernel, its eigenspectrum, or target alignment), from
      `RepresentationSimilarityReport` (linear-CKA on forward ACTIVATIONS, not
      gradients) and from `HessianCurvatureReport` (loss-surface curvature, not
      the gradient Gram). Ships with an `examples/NeuralTangentKernel/` demo
      (small classifier; contrast a wide vs narrow hidden layer to show the wide
      net's NTK drifting less) and the standard report test trio. Forward+
      backward only on a frozen net; weights are never stepped.

### Bugs surfaced by the introspection-report batch
- [ ] `TNNetFlipX.Backpropagate` (and likely `TNNetFlipY`) range-check
      overflow when the NEXT layer is a padded convolution: the flip layer's
      `OutputError` is sized exactly to its output, but a padded conv writes a
      larger (padded) error region into it, overflowing. Surfaced while wiring
      an `Input -> FlipX -> Conv -> ...` flip-invariant net for
      EquivarianceReport (worked around by using a global-avg construction
      instead). Add a numerical-gradient / forward+backward regression test
      for `FlipX -> padded Conv` and fix the unpad sizing.

### Tests / numerical-gradient audit
- [ ] Shared `LayerInputAndWeightGradientCheck(layer, inputShape)` helper
      in tests/TestNeuralNumerical.pas. Three-line tests instead of
      copy-pasted blocks. Should handle both input and weight central-
      difference checks with a `Tolerance` parameter (default 1e-2) so
      the DeMaxPool-style Double-precision SSE accumulator can be opted
      into per-test.
- [ ] Property-based gradient harness v0: randomize input shape (keeping
      layer type fixed) for the 6 most recently landed layers. Catches
      shape-edge bugs hand-written tests miss.
- [ ] Continue upsampling/deconvolution audit: TNNetDeconvolution input
      AND weight gradients (Upsample / DeMaxPool / DeAvgPool already
      covered). Likely benefits from the Double-precision SSE accumulator
      helper above.
- [ ] Recurrent-style layer audit: TNNetEmbedding's weight-gradient path
      (sparse-update pattern — easy place for a silent broadcast/reduction
      bug), TNNetTokenAndPositionalEmbedding, etc.
- [ ] Layer-registry round-trip audit — for every concrete TNNet* in the
      LoadFromString/CreateLayer dispatch table, instantiate with defaults,
      save, load, save again, assert bit-for-bit string equality. Highest-
      leverage single test for the "added a layer but forgot to register
      it" bug.
- [ ] Shape-inference smoke test — instantiate every concrete layer at a
      small canonical input shape, assert declared output shape matches
      actual.
- [ ] TestExtensions check: every layer that declares `FStruct[k]`
      constructor parameters should be tested for LoadFromString round-trip
      with NON-default values.
- [ ] Find-or-falsify pass: scan neuralnetwork.pas for any Backpropagate
      override whose body is just `inherited;` plus a tiny tweak — flag
      candidates for gradient-check coverage. The exact-softmax-Jacobian
      story teaches us how silent the diagonal-only bug class can be.
- [ ] Audit any remaining TNNet* layers that compute a softmax-like
      normalization (search for "Exp(" near a normalization loop) to
      confirm none still ship the diagonal-only approximation.
- [ ] Numerical-gradient stress test for TNNetSoftMax / TNNetPointwiseSoftMax
      across SeqLen / Depth / SizeX combinations.
- [ ] Backward audit for TNNetPointwiseNorm — its backward is the scalar-
      only `Mul(1/n)` approximation; TNNetL2Normalize now implements the
      exact Jacobian. Either replace or add a deprecation comment.
- [ ] Determinism test: same seed → bit-identical forward+backward across
      two runs of a 3-layer net.
- [ ] Random-architecture forward/backward fuzz — generate ~50 random
      stacks, seed-controlled, assert no NaN/Inf in forward, backward,
      or parameter gradients.
- [ ] Cross-layer composition gradient test: build a 3-layer stack
      (LayerNorm → SwiGLU → Dense) and run a single end-to-end central-
      difference check on the input.
- [ ] Activation derivative-cache invariants sweep: for each cache-using
      activation, run `Compute(A); Compute(B);` and assert FOutputErrorDeriv
      matches a fresh recomputation against B. Catches the Sigmoid-class
      stale-cache bug pattern.
- [ ] Activation golden-values regression test — for every registered
      activation, evaluate forward/backward on a pinned input at fixed
      seed and assert against pinned outputs within 1e-5.
- [ ] Per-activation derivative-sign sanity test — for each strictly
      monotone activation, assert FOutputErrorDeriv has the expected sign
      on a grid of inputs.
- [ ] Saturation-safety tests for TNNetTanhExp / TNNetSmish at ±extreme
      inputs, mirroring the HardTanh/SoftCapping pattern.
- [ ] TNNetDigital forward-equality test — pin threshold and output for
      three inputs straddling it (non-differentiable, so forward-only).
- [ ] TNNetMaxPoolWithPosition correctness check — the auxiliary "position
      channels" should round-trip through TNNetDeMaxPool to exactly
      reconstruct the upsample pattern.
- [ ] TNNetAddPositionalEmbedding scale-factor backward check on
      rectangular (X≠Y) shapes (square inputs can hide off-by-one bugs).
- [ ] Gradient-flow regression test — train a 12-layer ReLU MLP one epoch
      with and without a single TNNetLayerNorm/RMSNorm at the midpoint;
      assert per-layer gradient norms with the norm layer are uniformly
      bounded above the no-norm case.
- [ ] TNNetDotProducts numerical-gradient test — standalone class still
      ships, weight-gradient path looks like the kind of place a silent
      bug could live.
- [ ] TNNetLocalConnect / TNNetDeLocalConnect input + weight gradient tests.
- [ ] Kink-region test parametric helper: with Clamp / HardShrink /
      SoftShrink / Threshold / ShiftedReLU / HardTanh all in tree, the
      "no-central-difference, hand-picked kink convention" pattern
      repeats. Capture as `AssertKinkDerivative(layer, x_kink, expected_dydx)`.
- [ ] TNNetClamp kink-region test at `x = MinValue` and `x = MaxValue`.
- [ ] TNNetHardShrink / TNNetSoftShrink kink-region tests at hand-picked
      inputs (no central differences).
- [ ] TNNetSoftSign saturation test on ±1e6: assert `|y| < 1` and
      Backpropagate doesn't NaN.
- [ ] TNNetESwish saturation test at ±extreme inputs.
- [ ] LiSHT / BentIdentity gradient-magnitude sanity at large |x| — both
      grow unboundedly, finite-difference eps must scale with input
      magnitude.
- [ ] TNNetAbs near-zero gradient handling test — explicitly skip x = 0
      sampling and pin the convention (currently `sign(0) = 0`).
- [ ] TNNetSquare gradient-magnitude sanity test at large |x|.
- [ ] Shape-edge test for TNNetTokenShift: assert SetPrevLayer raises the
      documented error when SizeY > 1.
- [ ] Two-layer TokenShift composition test (catches subtle double-pass
      bugs in the t-1 / t+1 input-gradient scatter).
- [ ] TNNetStraightThroughEstimator `step ≤ 0` guard test.
- [ ] TNNetSoftMin saturation test on extreme inputs.
- [ ] Audit TNNetSigmoid and TNNetHardSigmoid for negative-x / positive-x
      symmetric-stability (same question as SoftPlus).
- [ ] Promote DeMaxPoolFamilyGradientCheck's Double-precision SSE
      accumulator into the shared LayerInputGradientCheck (and weight-grad
      variant). Sum the SSE in Double; eps and tolerance stay TNeuralFloat.
      NEW DATA POINT: TNNetAdaptiveMaxPool's gradient check hit the same
      float32 subtractive-cancellation issue (a single cell carrying the
      whole window error, num=1.2588 vs ana=1.2709) and had to be loosened
      to tol 0.02 with an in-code comment — verified NOT a layer bug
      (double-precision central difference matches analytic exactly). A
      strong candidate to convert once the Double accumulator helper lands.
- [ ] Add a "FP32 SSE accumulator warning" comment near LayerInputGradientCheck
      pointing future audits at the DeMaxPool case and the Double-precision
      workaround.
- [ ] TNNetPointwiseSoftMax: now that the exact Jacobian lives in
      Backpropagate, opt cross-entropy training paths into the cheap
      (y - target) shortcut explicitly, and add a regression test that
      checks the shortcut and the full-Jacobian path agree to 1e-5.
- [ ] TNNetSoftmaxTemperature refactor attempt: extract a shared softmax-
      Jacobian helper so SoftMax / PointwiseSoftMax / SoftmaxTemperature
      reduce to one Backpropagate body parameterised by axis +
      inv-temperature. Pure refactor, gradient tests pin behavior.
- [ ] Cross-entropy regression-style check: confirm classification
      examples (SimpleImage CIFAR) converge to the same loss curve they
      did before the TNNetSoftMax.Backpropagate exact-Jacobian change.
- [ ] Re-validate examples that use TNNetDeMaxPool / TNNetDeAvgPool after
      the gradient fix: DenseNet helper, VisualGAN, SuperResolution. The
      fix increases backward magnitude by `PoolSize` (=2 in practice), so
      existing learning rates may be off by 2x.
- [ ] Loss-layer gradient-check helper — parameterized helper that takes
      (LossLayer, BatchSize, Shape) and runs a single central-difference
      check.
- [ ] Scheduler unit tests — given seed and schedule parameters, NextLR
      must produce a deterministic, finite, monotonically-correct sequence.
- [ ] PrintSummary smoke test — capture summary output for canonical
      networks, assert row count and total-parameter line.
- [ ] Backward-pass sign-correlation test — for every layer that overrides
      Backpropagate, perturb input by ±ε, assert gradient direction agrees
      with loss-difference direction >90% of the time across a small grid.
- [ ] Coverage matrix at the top of TestNeuralNumerical.pas: per-class
      `[grad] [serialize]` block, written by a small script.
- [ ] LoadFromString round-trip for the entire activation menagerie — one
      parameterised test walking every TNNetReLUBase descendant.

### Tooling / dev experience
- [ ] `scripts/new_layer.sh <Name>` scaffolder — drops a Compute/Backpropagate
      skeleton into neuralnetwork.pas plus a numerical-gradient test stub.
- [ ] `scripts/new_activation.sh <Name>` scaffolder — narrower version for
      the most common landing type.
- [ ] `scripts/check_layer_dispatch.sh` — grep every `TNNet... = class`
      line, cross-reference against the two CreateLayer dispatch tables
      and the LoadFromString cascade, print any missing class.
- [ ] `scripts/audit_landed.sh` — companion to `audit_tasklist.sh`. Every
      `[x]` line claiming a TNNet* landed must point at a real class in
      the dispatch AND at least one Test* method.
- [ ] `scripts/audit_tasklist.sh --strict` mode — only match lines starting
      with the canonical `- [ ] TNNet… — …` re-pin shape. Two-line awk
      change; cuts the false-positive rate.
- [ ] `scripts/list_untested_layers.sh` filter pass: drop Base/Class/Abstract
      names, emit file:line for surviving entries.
- [ ] `scripts/audit_one_layer.sh <TNNet...>` — bundles grep_layer.sh,
      list_untested_layers.sh, and the numerical-gradient test runner
      filtered to tests that mention the layer.
- [ ] `scripts/plot_activation.sh <TNNet...>` — sample at 41 points in
      [-5, +5], print forward values and numerical derivative as a tiny
      ASCII chart. Pairs with a one-shot Pascal helper.
- [ ] `tests/SmokeTest.lpr` — five fastest gradient checks, exits in under
      a second. Real signal for a future CI shim.
- [ ] `tests/TestActivationMenagerie.pas` smoke test — walks every
      TNNetReLUBase descendant and confirms forward returns finite values
      on (-5, +5) spanning input.
- [ ] `--quick` flag on the test runner that skips heavier `SeqLen > 4`
      cases / `Slow` / `Large` markers.
- [ ] `--quick` flag on RunAll.sh that passes through.
- [ ] CI-friendly summary mode for the test runner: print a single
      "N passed / M failed" line plus failing-test names to stderr.
- [ ] `bin/layer_bench <ClassName> <SizeX> <SizeY> <Depth>` — tiny CLI
      that builds a 1-layer net and reports ns/op for forward + backward.
      Subsumes the long-pinned Volume micro-benchmark and extends it to
      layers.
<!-- (`neural-bench` CLI removed: duplicate of `bin/layer_bench` above, which
     already times forward+backward per layer at a chosen shape with CSV.) -->
### Examples I'd enjoy writing
- [ ] `examples/TinyGPT/` — char-level transformer end-to-end demo on
      a short text snippet (Tiny Shakespeare or repeated arithmetic).
      Highest-value example missing from the repo; natural capstone for
      the transformer-building-blocks line of work.
- [ ] `examples/DeadReLUDiagnostic/` — train a small ReLU net on MNIST
      and print the per-epoch fraction of units that never fire; repeat
      with LeakyReLU/GELU/Swish.
- [ ] `examples/AnomalyAutoencoder/` — train an autoencoder on MNIST
      digit "0", evaluate reconstruction error on all 10 digits, print
      AUROC.
- [ ] `examples/SpokenDigitKWS/` — 1D-conv keyword-spotting on FSDD:
      MFCCs → 1D conv stack → classification.
- [ ] `examples/TimeSeriesForecast/` — one-screen forecasting demo on a
      synthetic seasonal+trend series with a 1D-conv or tiny attention
      model.
- [ ] `examples/GradientFlowVisualizer/` — train a deep MLP with and
      without LayerNorm/RMSNorm and print per-layer gradient-norm tables
      across steps.
- [ ] `examples/NormalizationBakeoff/` — same idea comparing no-norm /
      BatchNorm / LayerNorm / RMSNorm / GroupNorm / InstanceNorm.
- [ ] `examples/OptimizerBakeoff/` — SGD / SGD+momentum / Adam / RMSProp
      on a fixed toy dataset with a loss-vs-epoch table.
<!-- (`examples/EmbeddingHeadDemo/` removed: duplicate of the landed
     `examples/TripletEmbedding/` example, which already learns a toy
     multi-class embedding with TNNetL2Normalize and prints the per-class
     cosine-similarity matrix. The only stated difference was a hand-rolled
     triplet loss vs the in-tree TNNetTripletLoss head — not worth a second
     near-identical demo.) -->
- [ ] `examples/EmbeddingVisualization/` — contrastive head on a 4-class
      toy 2D dataset, dump learned embeddings to CSV with README plotting
      instructions.
- [ ] `examples/MixUpAblation/` — train SimpleImageClassifier with and
      without MixUp on CIFAR-10 and report the delta.
- [ ] `examples/AttentionViz/` — load a tiny trained SDPA model and dump
      the per-head attention matrix as a PGM image.
- [ ] `examples/TinyTransformerFFN/` — SwiGLU + RMSNorm + residual FFN
      block on a toy denoising or autoregressive-bit task. No MHSA
      needed; demonstrates the FFN half-block.
- [ ] `examples/SubPixelSuperRes/` — once TNNetPixelShuffle lands, a
      3-layer net that learns to 2x-upsample 8x8 random checkerboards.
- [ ] `examples/BiasOnlyTuning/` — freeze a pretrained classifier and
      fine-tune only inserted TNNetChannelBias layers on a new task
      (BitFit-style cheap adaptation).
- [ ] `examples/AffineFineTune/` — once TNNetAffineBlock lands, same
      pattern but freezing everything except the inserted Affine blocks
      (built on TNNetChannelBias + TNNetChannelMul).
- [ ] `examples/TokenShiftBaseline/` — train a tiny next-token char model
      with `TNNetEmbedding → TNNetTokenShift → MLP` and compare against
      the eventual MHA-based version.
- [ ] `examples/ReZeroDeepMLP/` — train a 16-layer residual MLP with and
      without TNNetReZero on each residual branch on the hypotenuse toy.
- [ ] `examples/EuclideanNormHead/` — demo composing `Reciprocal(Sqrt(
      Square(x)))` as a Euclidean-norm-reciprocal head.
- [ ] `examples/SIREN/` — 1D periodic-function fit with TNNetSin.
- [ ] `examples/SpaceToDepthStem/` — show the SpaceToDepth → Conv stem
      replacing a stride-2 conv on a tiny CIFAR stub.
- [X] `examples/PreNormVsPostNorm/` — same 12-block deepish residual MLP
      wired three ways via AddPreNormResidual / AddRMSNormResidual /
      AddPostNormResidual, trained on the synthetic hypotenuse task at
      matched seed/LR/epochs. LANDED (2026-05-24 lucky-day batch): surfaces
      the textbook stability gap (pre-norm arms → near-zero error; post-norm
      oscillates and ends ~10x higher, val MSE ~1000x worse), handles NaN/Inf
      cleanly, runs ~40s on CPU. Follow-up worth adding: push NUM_BLOCKS / LR
      until post-norm goes full NaN (`diverged = YES`) to show the harder
      divergence the harness already guards against; and an AddGatedResidual
      fourth arm (the builder also landed this batch).
- [ ] `examples/MaxoutMnist/` — minimum-viable Maxout demo on a tiny-MNIST
      subset (or synthetic 2D classification).
- [ ] `examples/ModelSummaryDemo/` — three networks printed via
      PrintSummary; doubles as a smoke test for the summary output format.
- [ ] `examples/SchedulerCompare/` — same network trained four times with
      constant LR, StepLR, CosineLR, WarmupCosineLR; one chart.
- [ ] `examples/SWADemo/` — CIFAR-10 baseline vs same network with SWA
      enabled from epoch 75% on.
- [ ] `examples/LossLandscapeCompare/` — MSE vs LogCosh vs Huber vs MAE
      on Hypotenuse with a handful of injected outliers.
- [ ] `examples/QuantizationAwareMnist/` — STE-MNIST demo: baseline vs
      STE on penultimate activation, compare test accuracy and final-weight
      histograms.
- [ ] `examples/CharbonnierSR/` — minimal variant of SuperResolution that
      swaps the MSE head for TNNetCharbonnierLoss and prints PSNR delta.
- [ ] `examples/SparseAttentionDemo/` — once TNNetSparsemax lands, toy
      "predict next char of a periodic sequence" using Sparsemax in place
      of softmax over a tiny K|V bank. Print attention-weight histogram
      per step.
- [ ] `examples/FiLMConditional/` — toy "draw a digit of class C" generator
      with FiLM conditioning on a 10-way one-hot class input.
- [ ] `examples/TripletEmbedding/` MNIST follow-up: a true MNIST version of the
      landed synthetic TripletEmbedding demo, with a PGM scatter-plot output.
- [ ] `examples/VQAutoencoder/` — extend VisualAutoencoder with a
      TNNetVectorQuantizer bottleneck.
- [ ] `examples/AntiAliasedMaxPool/` — train the same tiny CIFAR-10 net
      once with TNNetMaxPool and once with TNNetMaxBlurPool; report
      shift-equivariance delta.
- [ ] `examples/ReverseXYAugmentation/`, `examples/AutoencoderMNIST/`,
      `examples/AutoencoderReconstructionGrid/` — additional small demos.
- [ ] `examples/ActivationPlayground/` — prints one CSV row per activation:
      name, forward ns/op, backward ns/op, output range on [-8, 8],
      derivative range, "is monotone?" check.
- [ ] `examples/ActivationGallery/` — constructs a single-layer net per
      activation, sweeps inputs `x ∈ [-5, 5]`, prints `(x, y, dy/dx)`.
      Smoke test that every activation's forward + cached derivative
      agree with their textbook formula.

### Experiments I'm curious about (additional)
- [ ] LogSoftMax+NLL vs SoftMax+CE convergence parity test: same seed,
      same tiny classifier, plot val-loss curves.
- [ ] InstanceNorm vs GroupNorm vs LayerNorm vs ChannelStdNorm single-seed
      bake-off on a 3-layer CIFAR-ish conv stack.
- [ ] Shrink-activation sparsity sweep: ReLU / SoftShrink / HardShrink as
      bottleneck activations, sweep lambda over `{0.1, 0.25, 0.5, 1.0}`,
      report (sparsity %, recon loss).
- [ ] Activation "kink at zero" finite-difference noise audit on every
      activation on a `[-0.05, 0.05]` window stepping by 1e-3.
- [ ] Periodic-activation toy benchmark — fit `y = sin(3x) + 0.3 sin(11x)`
      with TNNetSnake vs ReLU/GELU/Tanh MLPs of equal width/depth.
- [ ] Sinc-vs-Sin head-to-head on the SIREN-flavored fit.
- [ ] Dropout-vs-DropPath head-to-head — same small CIFAR model with
      element-wise TNNetDropout and whole-sample TNNetDropPath at matched
      effective drop rates.
- [ ] LeCunTanh-vs-Tanh ablation reproduction with a small seed/LR sweep
      on top of examples/HyperbolicActivationBakeOff/. Average over 5 seeds
      and report mean+std.
- [ ] Charbonnier-vs-Huber-vs-MSE-vs-LogCosh head-to-head on the noisy-
      hypotenuse harness.
- [ ] Loss-family bake-off (output heads): hypotenuse with MSE / Huber /
      SmoothL1 / Charbonnier / LogCosh, printing final MSE and epochs-to-
      converge.
- [ ] TanhGLU vs SwiGLU vs GEGLU vs GLU vs ReGLU bake-off: same tiny seq
      model, swap the gating layer, chart final loss and wall-clock.
- [ ] LogCoshDualExperiment longer-horizon follow-up: 200-300 epochs and
      5 seeds (mean ± std reporting).
- [ ] Plain-Tanh vs TanhGLU FFN ablation in a minimal-transformer-without-
      attention skeleton.
- [ ] DyT-vs-LayerNorm bake-off. TNNetDyT has now landed, so this is
      unblocked — a 30-line swap in the existing normalization bake-off
      harness (or a small standalone synthetic-regression A/B).
- [ ] Causal-conv vs token-shift vs SDPA on the same toy next-token task.
- [ ] GRN-as-drop-in: take SimpleImage CIFAR, swap each
      TNNetMovingStdNormalization for TNNetGRN and chart accuracy.
- [ ] TNNetChannelBias-vs-TNNetChannelMul ablation: train a small
      classifier four ways — (a) no affine, (b) bias only, (c) mul only,
      (d) both — print final accuracy and learnable params per variant.
- [ ] Maxout vs ReLU width-trade study at matched parameter count.
- [ ] Sinusoidal vs learned positional embedding head-to-head on the
      binary-addition task.
- [ ] PReLU vs LeakyReLU vs RReLU on a tiny CIFAR stub at matched param
      count. (UNBLOCKED: TNNetRReLU has now landed — remember to flip its
      `Enabled` flag off for the eval pass so the fixed average slope is used.)
- [ ] TopK sparsity sweep: train the same tiny autoencoder bottleneck
      with K ∈ {1, 2, 4, 8, 16, full}, chart reconstruction loss vs sparsity.
- [ ] STE bit-width sweep: same network, vary `step ∈ {1.0, 0.5, 0.25,
      0.125, 0.0625}`, plot accuracy vs bit-width.
- [ ] Straight-through quantization demo: small classifier with one hidden
      layer's outputs passed through a TNNetStraightThroughEstimator;
      compare accuracy against unquantized baseline.
<!-- (Lottery-ticket sanity check removed: duplicate of the "Lottery-ticket"-
     flavored experiment under "Bake-off / experiment follow-ups".) -->
- [ ] Sequence-length scaling micro-benchmark — TNNetScaledDotProductAttention
      at seq_len ∈ {16, 32, 64, 128, 256} with d_k fixed. Confirms O(n²)
      scaling.
- [ ] Channel-attention bake-off: fixed tiny CIFAR backbone, four variants
      — (a) no attention, (b) SE, (c) CBAM, (d) hand-rolled "1x1 + sigmoid".
- [ ] FiLM-vs-concat conditioning bake-off on a class-conditional MNIST
      decoder.
- [ ] VQ codebook collapse stress test: K in {16, 64, 256} and a few
      commitment-loss weights, report per-run active codebook entries.
- [ ] "Tiny induction-heads" demo: train a 2-layer attention-only model on
      a repeat-the-pattern toy task and show the second layer's attention
      diagonal jumps to the previous-occurrence position.
- [ ] "Memorize a sentence" demo: train a 1-layer SDPA+RoPE model to
      perfectly memorize a 32-token sequence, print training loss curve
      and reconstructed sample.
- [ ] "Learn to reverse" toy: SeqLen=8 input → output the reversed sequence.
- [ ] "Smallest net that can learn parity-N" study — sweep N ∈ {2, 4, 6, 8}.
- [ ] Grokking demo (`examples/Grokking/`) — reproduce delayed generalization
      (Power et al. 2022) on a pure-CPU toy. Train a tiny MLP on modular
      addition `(a + b) mod P` for a small prime (e.g. P=23 → 529 input
      pairs), one-hot inputs concatenated, softmax over P classes, with a
      fixed ~40/60 train/val split and weight decay on. The headline is the
      curve shape: train accuracy hits 100% early while val accuracy stays
      at chance for many epochs, then *suddenly* jumps to ~100% long after
      the training loss flatlines. Print a two-column ASCII chart of
      train-acc vs val-acc over a log-spaced epoch axis and flag the
      "grok epoch" (first epoch where val-acc crosses a threshold, well
      after train-acc saturates). Distinct from the parity-N capacity
      study (that asks "can it fit at all?", not "when does it
      generalize?") and from the "memorize a sequence" demo (which never
      generalizes by design). A small ablation toggling weight decay
      on/off makes the point that the regularizer is what eventually drives
      the late generalization. Pairs naturally with [[WeightSpectrumReport]]
      / [[WeightHistogramReport]] to watch the weights reorganize at the
      grok transition.
      ATTEMPTED 2026-05-24 (lucky-day batch) — NOT shipped, findings to
      save the next attempt: (1) the clean weight-decay-driven jump to ~100%
      val accuracy is NOT reproducible within the ~5-minute CPU budget here —
      the library's full-batch Adam is slow/unstable at the LRs grokking
      needs, so the thousands of epochs required do not fit the budget.
      (2) CONCATENATED one-hot input (depth 2P) never generalizes (val ~0): the
      two independent input weight-blocks act as a pure lookup table and weight
      decay cannot align them. (3) SUMMED one-hot input (depth P) DOES show
      delayed generalization (train ~100% by ~epoch 200, val lags near chance
      then climbs to a ~0.5 plateau) but weight decay made NO difference at
      this scale. Even the summed variant with two runs + P=23 ran >4m50s and
      blew the budget. SUGGESTED BREAKDOWN for a future attempt that fits the
      budget: (a) ship the reproducible *representation contrast* alone
      (concat-never-generalizes vs summed-delayed-generalizes) as a fast
      single-run demo, dropping the weight-decay claim; OR (b) first add a
      faster optimizer / mini-batch path so enough epochs fit, THEN retry the
      true grok. Do not re-attempt the full weight-decay grok as a single
      monolithic example until (b) lands.
- [ ] Double-descent demo (`examples/DoubleDescent/`) — reproduce the
      model-wise "double descent" risk curve (Belkin et al. 2019; Nakkiran
      et al. 2020, *Deep Double Descent*) on a pure-CPU toy. The headline is
      a phenomenon that NONE of the in-tree experiments show: as model
      CAPACITY grows, test error first FALLS (classical bias-variance), then
      RISES to a sharp peak right at the *interpolation threshold* (where the
      net has just enough parameters to fit the noisy training set exactly),
      then FALLS AGAIN and keeps improving in the heavily over-parameterised
      regime — a non-monotone U-then-down curve, not the usual monotone one.
      Recipe: fix a SMALL training set (e.g. 40-80 samples) with a few
      percent LABEL NOISE injected (the noise is what makes the peak sharp
      and visible), hold out a clean validation set, then train the SAME tiny
      MLP at a sweep of hidden widths spanning under- to over-parameterised
      (e.g. `H in {2,4,8,16,24,32,48,64,96,128}`, so param-count straddles
      the train-set size), each to ~full convergence (high epochs / low LR so
      the small models actually interpolate), and chart a two-row ASCII curve
      of train-error and test-error vs `log2(param_count)`. Flag the
      empirical interpolation threshold (smallest width whose train error
      first hits ~0) and check that the test-error PEAK lands at/just past it
      (the built-in correctness signal — no peak ⇒ noise too low or models
      not trained to interpolation). A small ablation toggling label noise
      on/off makes the point that the peak is noise-driven (the clean-label
      curve is ~monotone). DISTINCT from the open grokking demo (delayed
      generalization over TRAINING TIME at FIXED capacity — a time axis,
      driven by weight decay) and from the open "Width vs depth at fixed
      parameter budget" heatmap (a fixed-budget val-loss grid with no noisy
      interpolation peak and no capacity SWEEP past the threshold): this is a
      generalization-vs-CAPACITY axis and the non-monotone peak is the whole
      point. Pure CPU, no external data, should fit a few-minute budget if the
      widths and sample count are kept tiny. Pairs naturally with
      [[WeightSpectrumReport]] / [[WeightHistogramReport]] (watch the weight
      norm spike at the interpolation threshold) and with the open
      MagnitudePruning lottery-ticket follow-up (over-parameterised models are
      the compressible regime on the right arm of the curve).
- [ ] Toy-models-of-superposition demo (`examples/Superposition/`) — reproduce
      the headline result of Anthropic's *Toy Models of Superposition* (Elhage
      et al. 2022) on a pure-CPU toy: a network packs MORE sparse features than
      it has dimensions by storing them in **superposition** (non-orthogonal,
      mutually-interfering directions), and the geometry it picks is governed by
      feature SPARSITY. Recipe with existing layers only — no new layer needed:
      generate synthetic feature vectors of width `N` (e.g. N=20) where each
      feature is independently active with probability `(1 - S)` (sparsity `S`)
      and drawn ~U[0,1] when active, assign per-feature IMPORTANCE weights
      `I_i = r^i` (geometric decay), and train the autoencoder
      `Input(N) -> TNNetFullConnectLinear(M)  {= encoder W, M<N, e.g. M=5} ->
      TNNetFullConnectReLU(N) {= decoder + bias + ReLU}` to reconstruct the
      input under an IMPORTANCE-WEIGHTED MSE (weight each output dim's squared
      error by `I_i` — the weighting is what makes the model choose WHICH
      features to represent, the crux of the phenomenon). The classic model ties
      decoder = encoder^T to study `W^T W`; with untied FC layers read the
      effective pre-ReLU linear map `D·W` (N×N) instead and treat its
      off-diagonals as the interference — document the tied-weight ideal and this
      practical untied realization. Report, per sparsity level: the per-feature
      represented-norm `||column_i||` as an ASCII bar (which features the model
      kept vs dropped to zero), the N×N Gram/interference matrix `(D·W)` as a
      glyph-shaded heatmap (a near-identity at low sparsity = monosemantic,
      one-feature-per-direction; growing off-diagonal blocks at high sparsity =
      polysemantic superposition), a scalar **superposition ratio** = (count of
      features with non-trivial norm) / M (≈1 when dense → the model represents
      only M features orthogonally; >1 when sparse → it crams in extras), and the
      mean off-diagonal `|interference|`. Sweep `S ∈ {0.0, 0.7, 0.9, 0.99}` to
      show the phase transition from "represent the top-M features orthogonally,
      drop the rest" (dense) to "represent nearly all N features in superposition
      with structured interference" (sparse) — the textbook antipodal-pairs →
      polytope progression. Built-in correctness signals: at S=0 (dense inputs)
      the kept-feature count must be ≈ M and the Gram ≈ a rank-M near-diagonal
      (no superposition is optimal when features collide every sample); the
      represented set must track importance (high-`I` features are kept first);
      and total represented norm should grow as S rises. Pure CPU, no external
      data, fits a few-minute budget at these tiny sizes. DISTINCT from
      everything in tree: the grokking / double-descent demos vary TRAINING TIME
      / CAPACITY and watch a loss curve, not feature geometry; the
      [[FeatureSeparabilityReport]] / NeuronCorrelationReport /
      RepresentationSimilarity / IntrinsicDimension reports all DIAGNOSE a given
      trained net's activations (class scatter, neuron redundancy, CKA, PCA-ID) —
      none reproduce the sparse-feature-packing phenomenon or sweep sparsity to
      surface the monosemantic↔polysemantic transition. Pairs naturally with
      [[WeightSpectrumReport]] (the bottleneck's spectrum fills in as features
      enter superposition) and the open dictionary-learning / sparse-coding line
      of interpretability work.
- [ ] "Surgery" experiment: train a small classifier, then zero out the
      top-K most-active hidden units and chart accuracy degradation vs K.
<!-- (Plain "label-smoothing sweep — tabulate test accuracy" removed:
     subsumed by the "LabelSmoothing calibration check" entry under
     "### Loss layers", which runs the SAME SimpleImageClassifier sweep over
     the SAME eps ∈ {0, 0.05, 0.1, 0.2} and additionally feeds each into the
     neuralcalibration ECE/Brier report — a strict superset.) -->
- [ ] SWA effect-size sweep: vary SWA start-epoch fraction ∈ {0.5, 0.6,
      0.7, 0.8, 0.9} and chart final test accuracy.
- [ ] Cosine-LR vs constant-LR on SimpleImageClassifier, three seeds each.
<!-- ("Activation cost" microbenchmark removed: duplicate of the per-activation
     forward/backward ns/op CSV in `examples/ActivationPlayground/` and of
     `bin/layer_bench <Activation> 64 64 32` under "Tooling / dev experience",
     both of which already time forward+backward per activation/layer at a
     chosen shape.) -->
- [ ] Activation saturation visualizer: train a tiny net with Sigmoid /
      Tanh / HardSigmoid and print the fraction of saturated units per
      layer per epoch.
- [ ] "Where does the gradient go?" visualizer for in-tree saturation
      activations: for each of HardTanh / SoftCapping / Clamp / ReLU6 /
      SoftSign / Tanh, feed a 1D ramp and print y(x), dy/dx as PGM strips.
- [ ] Softmax-vs-SoftMaxOne-vs-Sparsemax bake-off as a pure-forward-pass
      comparison: same Q,K,V tensors, print entropy and max-weight of each.
- [ ] SDPA + TNNetSoftMaxOne micro-experiment: replace the softmax inside
      SDPA with SoftMaxOne and check whether attention-mass on a "all-keys-
      irrelevant" probe sequence drops toward zero. Needs either a flag
      on SDPA or a small standalone wiring.
- [ ] Softmax stability micro-test: feed a deliberately huge logit vector
      (`x = [1000, 0, 0, ...]`) through TNNetSoftMax / TNNetLogSoftMax;
      assert finite output, finite gradient, sum-to-one within 1e-6.
- [ ] PixelNorm Jacobian-blow-up empirical test at `||x|| ∈ {1, 1e-2,
      1e-4, 1e-6, 1e-8, 1e-10}`; record central-difference vs analytic-
      gradient relative error.
- [ ] L2Normalize vs PixelNorm head comparison on a tiny generator-shaped
      net.
- [ ] "Does exact-softmax-Jacobian matter?" controlled experiment: same
      classification example with new exact Jacobian vs old diagonal
      approximation restored on a branch.
- [ ] Polynomial-activation bake-off micro-experiment: swap each TNNetReLU
      in a small MLP for TNNetPolynomialActivation, compare final loss on
      the hypotenuse toy.
- [ ] Threshold-as-sparsifier sweep: theta ∈ {0, 0.1, 0.5, 1.0}, report
      (active-units %, recon loss) on a 64-unit autoencoder.
- [ ] Activation derivative-at-zero study: plot Compute + ChainDeriv
      around x=0 for ReLU, GELU, Swish, Mish, CELU, ELU on a [-2,2] grid.
- [ ] Width vs depth at fixed parameter budget on a tiny MNIST-shaped
      task: 4 widths × 4 depths, plot val-loss heatmap.
- [ ] Init-scheme sensitivity heatmap — ASCII heatmap of per-layer
      activation magnitudes across init schemes for a deep ReLU MLP.
- [ ] Flip-augmentation efficacy sweep: TNNetFlipX/Y at p ∈ {0, 0.25,
      0.5, 0.75, 1.0} on a synthetic orientation task.
- [ ] CELU vs ELU alpha-sensitivity micro-experiment: sweep `alpha in
      {0.1, 0.5, 1.0, 2.0}` for both.
- [ ] ESwish vs Swish bake-off: β ∈ {1.0, 1.25, 1.5, 2.0}.
- [ ] TNNetSnake α-sweep: fit `f(x) = sin(8x)` with a 3-layer Snake MLP
      across α ∈ {0.5, 1, 2, 4}.
- [ ] Trig identity composition tests: `Sin(x)² + Cos(x)² = 1`, Snake at
      α=1 derivative trig identity.
- [ ] Test that `TNNetNegate.Compose(TNNetNegate)` round-trips to identity.

### Norm / extra audits
- [ ] PixelNorm + StyleGAN-flavored generator micro-example (the layer's
      headline use case; pairs with VisualGAN).
- [ ] PixelNorm vs InstanceNorm vs no-norm bake-off on a tiny generator-
      shaped net.
- [ ] TNNetInstanceNorm CIFAR-style integration example (SimpleImage path
      with InstanceNorm replacing ChannelStdNorm).
- [ ] CIFAR/segmentation example using TNNetReverseChannels — channel-flip
      data augmentation as headline use case.
- [ ] CIFAR/ImageNet-style ShuffleNet block example (1x1 conv →
      ChannelShuffle → depthwise conv) integrated into one of the SimpleImage
      paths.
- [ ] ChannelShuffle group-count sweep: train the same tiny conv net with
      `groups ∈ {1, 2, 4, 8}` and chart accuracy.
- [ ] "Does ChannelShuffle help small models?" experiment on SimpleImage
      CIFAR at matched parameter count.
- [ ] "Why bother with a learnable per-channel scale?" experiment: train
      two deep MLPs (one with a small-init TNNetChannelMul on each
      residual branch, one without) on a toy regression task; chart
      per-layer gradient norms.
- [ ] DropPath-strict-drop teaching artifact: confirm a deep residual net
      with p=1 DropPath after every block collapses to the identity-path
      loss curve.
- [ ] LogSigmoid + BCE-with-logits training-loss smoke example.
- [ ] LogSigmoid kink-region test at the `x=0` branch crossover.
- [ ] Threshold "kink at theta" test at hand-picked x = theta documenting
      the chosen convention.
- [ ] TNNetMaxOut serialization-after-wire test: build a small net with
      MaxOut in the middle (so SetPrevLayer fires post-load), save/load
      whole net via SaveToString/LoadFromString, assert Compute matches
      end-to-end.
- [ ] TNNetMaxOut CIFAR-style example wired into one of the SimpleImage
      paths.
- [ ] TNNetCELU CIFAR-style smoke example.
- [ ] TNNetHardShrink / TNNetSoftShrink sparsity micro-experiment: train a
      tiny autoencoder with each as the bottleneck activation, print
      fraction of zero activations vs reconstruction loss.

### Documentation I'd enjoy writing
- [ ] "Activations cheat sheet" in `docs/activations.md`: one row per
      activation with formula, derivative, saturating?, smooth-at-zero?,
      typical use case.
- [ ] `docs/activation_taxonomy.md` — organise the ~50 activations now in
      the repo by mathematical family.
- [ ] "Saturation activations cheat sheet" in `docs/saturation.md` covering
      Clamp / HardTanh / SoftCapping / ReLU6 / SoftSign / Tanh / HardSigmoid.
- [ ] "Periodic activations" README subsection covering TNNetSin, TNNetCos,
      TNNetSnake, TNNetGaussianActivation.
- [ ] "Sparsity & routing" README subsection covering TNNetTopK,
      TNNetHardShrink, TNNetSoftShrink, TNNetThreshold (TopK has landed).
- [ ] "Elementwise transcendental layers" README subsection covering
      TNNetSqrt / TNNetExp / TNNetLog / TNNetReciprocal / TNNetAbs /
      TNNetSquare. Common eps-guard convention plus a tiny Euclidean-norm-
      reciprocal composition snippet.
- [ ] "Involution layers" README subsection covering TNNetReverseChannels /
      TNNetReverseXY / TNNetFlipX / TNNetFlipY. One paragraph plus a
      `Net.AddLayer([TNNetFlipX.Create(), TNNetFlipX.Create()])` identity
      snippet.
- [ ] "Bounded activations" README subsection covering Sigmoid, Tanh,
      HardSigmoid, HardTanh, SoftSign.
- [ ] "Building a transformer block" README walkthrough — pull
      TNNetMaskedFill / SDPA / RotaryEmbedding / GEGLU / SwiGLU /
      LayerNorm / RMSNorm references into one walkthrough with a single
      assembled code snippet. Blocked only on MHSA.
- [ ] "Loss functions" README subsection grouping MSE, MAE, CE, Huber,
      SmoothL1, LogCosh, Charbonnier, and (once landed) Dice/KL/Focal/
      LabelSmoothing/CosineEmbedding into a single short table.
- [ ] "Robust regression losses" README entry under
      TNNetHuberLoss / TNNetSmoothL1Loss / TNNetLogCoshLoss /
      TNNetCharbonnierLoss.
- [ ] "Learning-rate schedulers" README subsection — one paragraph per
      schedule with a snippet showing how to wire it into TNeuralImageFit
      (once the scheduler interface lands).
- [ ] "Introspection" README subsection — group CountLayers/Neurons/Weights
      with the new PrintSummary / FLOPs / WeightHistogram / DeadNeuronReport
      utilities.
- [ ] "Layer index by family" README appendix — alphabetical-within-family
      table (Convolution / Pooling / Activation / Normalization / Attention
      / Loss / Shape / Regularization).
- [ ] "Position encodings in this repo" comparison page covering sinusoidal
      AddPositionalEmbedding, RoPE, and ALiBi: when each is the right pick,
      input expectations, code snippets.
- [ ] "Softmax variants in this repo" note: TNNetSoftMax, TNNetPointwiseSoftMax,
      TNNetSoftmaxTemperature, TNNetSoftMin, TNNetSoftMaxOne, TNNetLogSoftMax
      — when to pick each, which axis, exact vs approximate Jacobian.
- [ ] `docs/numerical_gradient.md` — short tutorial: why central differences,
      how the existing TestNumericalGradient helper works, how to add a
      test in five lines. Includes a "non-differentiable forward" pattern
      note (STE is the first in-tree layer where central-difference is
      provably wrong).
- [ ] "How to add a new layer" cookbook anchored to a real recent landing
      step by step from constructor declaration through CreateLayer dispatch
      to the numerical-gradient test.
- [ ] "How to add a new activation in ~30 lines" walkthrough — reuses
      TNNetReLUBase with a worked example.
- [ ] "Elementwise activation layer authoring" mini-guide capturing the
      recurring 4-step pattern (Compute, Backpropagate via FOutputErrorDeriv,
      dispatch entry, four-test shape).
- [ ] `docs/channel_attention.md` — once SE / CBAM / FiLM land, compare
      them on the same axes.
- [ ] `docs/loss_layers.md` — once the loss family is complete, table input
      shape required, scalar vs per-sample, drop-in vs auxiliary.
- [ ] Short note in `tests/README` on "how to add a numerical-gradient
      test in three lines" cookbook for the shared helper.
- [ ] CHANGELOG.md / "What's new" section — one bullet per landed layer
      with date + commit short SHA.
- [ ] `docs/lucky_day_log.md` — rolling changelog of what each lucky-day
      batch shipped, letting tasklist.md itself be pruned of historical
      batches.
- [ ] Auto-generator for `docs/layer_taxonomy.md` walking the class
      hierarchy of TNNetLayer and emitting a tree.
- [ ] Inline-comment cleanup pass on TNNetScaledDotProductAttention: shape
      annotations on every loop, named strides, link to the planned
      annotated walkthrough.
- [ ] Annotated SDPA walkthrough: softmax-Jacobian derivation, shape
      annotations, worked tiny example (d_k=2, SeqLen=2).
- [ ] Annotated TNNetSoftmaxTemperature.Backpropagate walkthrough: full
      softmax-Jacobian derivation with shapes on every line.
- [ ] Doc-comment pass on the activation layers added in recent batches
      (GEGLU, SwiGLU, DropPath, RotaryEmbedding) so the auto-generated
      layer reference has clean source to pull from.
- [ ] README "What landed this month" entry: SDPA, RoPE, MaskedFill,
      SoftCapping, DropPath, GEGLU/SwiGLU/GLU, SquaredReLU, LayerScale,
      SpatialDropouts. One line each.
- [ ] One-pager "transformer building blocks landed in this repo": table
      of LayerNorm / MaskedFill / SDPA / RoPE / SoftCapping / DropPath /
      GEGLU / SwiGLU / GLU / SquaredReLU / LayerScale / AddPositionalEmbedding
      / ChannelShuffle / ALiBi / TanhGLU with "what it is" + "use it when".
- [ ] Short "where the test suite lives" map: tests/TestNeuralNumerical vs
      older `tests/*` programs, how RunAll.sh orchestrates them.
- [ ] "Gradient-check failure triage protocol" note: when a new numerical-
      gradient test fails, the bug is almost always in the layer under test,
      not the test harness. Document the DeMaxPool case as the canonical
      worked example.

### Stretch / ambitious
- [ ] `examples/TinyDiffusion/` — a 20-step denoising-diffusion model on
      8x8 grayscale MNIST patches using a tiny FiLM-conditioned U-Net with
      TNNetSinusoidalTimeEmbedding. Depends on FiLM + timestep embedding.
- [ ] `examples/HopfieldRetrieval/` — modern Hopfield network as attention
      (Ramsauer et al.): store K patterns, retrieve via a single softmax-
      attention step against a query.
- [ ] Mixed-precision experiment first step: add `TNeuralFloat16 = packed
      record ...` in neuralvolume.pas with conversion helpers, plus a
      one-layer forward-only test validating FP16 matches FP32 to within
      1e-2.

### Introspection (added)
- [ ] FeatureSeparabilityReport follow-up (now landed): the scatter-
      decomposition identity `tr(Stot)=tr(Sw)+tr(Sb)` is only exact for
      class-balanced batches (the report uses class-balanced `mean_c`
      definitions and prints the worst residual). Add a count-weighted scatter
      mode so the identity holds exactly for imbalanced probe batches too,
      gated by a flag (balanced stays default). Re-pin the smoke-test
      assertion under the weighted mode.
- [ ] FeatureSeparabilityReport follow-up: a training-trajectory variant that
      calls the report every N epochs on a fixed probe set and charts
      `tr(Sw)` collapse + Fisher-ratio climb over training — the cleanest
      single-number window into the terminal phase / neural collapse. Pairs
      with the open grokking / lottery-ticket experiments
      ([[WeightSpectrumReport]]).
- [ ] ModeConnectivityReport follow-up: make the connected/weak-barrier/
      separated verdict robust when the endpoint losses are near zero. As
      landed, the verdict uses a barrier-relative-to-endpoint-loss ratio, so
      the same-basin run (barrier ~3e-5 on an endpoint loss ~3e-4) misreads
      as "weak barrier" purely because the denominator is tiny. Add an
      absolute-floor term (e.g. treat barriers below an absolute epsilon as
      "connected" regardless of ratio) and re-pin the example's RUN 1 verdict.
- [ ] TNNet.PredictionDepthReport(NN, Support, SupportLabels, Queries
      [, K, QueryLabels]) — a **per-example difficulty** diagnostic built on
      the *prediction depth* of Baldock, Maennel & Neyshabur 2021 ("Deep
      Learning Through the Lens of Example Difficulty"), answering a question
      none of the landed reports answer: *"at how deep a layer does the network
      actually make up its mind about THIS example?"* — a per-sample resolution
      depth, not a per-layer aggregate. The recipe is forward-only and
      non-parametric: run one forward pass over a labelled **support** batch and
      over the **query** batch, snapshot each layer's flattened activation, and
      for every query, at every trainable layer, take a **k-NN vote** (default
      K=5, cosine distance) over the support activations at that same layer. The
      *prediction depth* of a query is the index of the **shallowest layer after
      which the k-NN vote agrees with the network's final argmax and never
      disagrees again** (deeper layers all confirm it) — easy examples are
      decided early (shallow depth), hard / ambiguous / mislabelled examples stay
      contested until the last layers (deep depth). Reports: a 10-bin ASCII
      histogram of prediction depth across the query batch, mean / median depth,
      the per-layer "newly-resolved" count (how many queries first lock in at
      each layer — a depth-vs-layer profile), the K deepest (= hardest) query
      indices as a ready-made hard-example / relabel-candidate queue, and — when
      `QueryLabels` are supplied — a correctness cross-tab (mean prediction depth
      of correctly vs incorrectly classified queries; the literature's headline
      result is that depth correlates with error and with margin). Over-wide
      layers are random-projected to a `MaxFeatDim` cap (default 256) to bound
      the distance cost, reusing the projection trick already in
      [[LinearProbeReport]]. Built-in correctness checks: feeding the **support
      set as its own queries** must give every sample a finite depth and the
      final-layer k-NN vote must match the network argmax for ≥ a high fraction
      (the support is its own nearest neighbour at distance 0); a query whose
      final argmax is already the majority vote at layer 0 reads depth 0; and a
      one-class support set drives every depth to 0 (trivially agreeing). The
      story for the example: at fresh init prediction depths pile up at the
      LAST layer (nothing is resolved early — the histogram is right-skewed),
      while after training the mass shifts shallow for the well-separated
      clusters and a hard / label-noised subset keeps a deep tail — example
      difficulty made visible. **Distinct from** [[LinearProbeReport]] (fits a
      *parametric* ridge classifier per layer and reports per-layer *accuracy* /
      decodability — a global "where does the net become linearly separable?"
      number, not a per-example depth, and it needs a matrix solve where this
      needs only distances), from `FeatureSeparabilityReport` (per-layer *cluster
      geometry*, label-aware but aggregate, no per-sample score), from
      `TopLogitMarginReport` (output-logit margin only — a confidence number at
      the *last* layer, with no notion of *which* layer resolved the example),
      and from `MCDropoutUncertaintyReport` (stochastic epistemic uncertainty,
      not a deterministic depth). Follows the introspection-report-pattern:
      declaration + impl in neuralnetwork.pas, a `examples/PredictionDepth/` demo
      on a synthetic multi-class 2D-blob set (a clean split plus a deliberately
      label-noised subset so the easy-shallow / hard-deep contrast and the
      correct-vs-incorrect depth gap are visible in one run), and a smoke test in
      tests/ (non-empty report, expected header, nil-NN graceful return, plus the
      support-as-its-own-queries finite-depth / final-layer-agreement assertion).
      Pairs naturally with the active-learning queue use of
      [[MCDropoutUncertaintyReport]] and the hard-example pools of
      `TopLogitMarginReport` / `ConfusionMatrixReport`.
- [ ] TNNet.LogitLensReport(NN, Probes [, HeadStartIdx]) — the **logit-lens**
      diagnostic (nostalgebraist 2020; "Tuned Lens", Belrose et al. 2023),
      answering a question none of the landed reports answer: *"if we read out
      the prediction at THIS layer using the network's OWN trained output head,
      what would it already say?"* — the model's running, self-decoded belief at
      each depth, using ZERO fitted parameters. The recipe is forward-only: run
      one forward pass over an unlabelled probe batch, identify the trailing
      "head" sub-stack (the layers from `HeadStartIdx` to the output — default:
      the last trainable layer plus any pure activation/softmax tail, i.e. the
      classifier readout), then for every EARLIER layer whose flattened
      activation is shape-compatible with the head's expected input, splice that
      activation into the head and recompute ONLY the head layers to obtain a
      per-layer "lens distribution" `p_L`. It reports: the per-layer agreement
      rate `mean_x[argmax(p_L) == argmax(p_final)]` as an ASCII bar chart across
      depth; the **crystallization depth** (shallowest layer after which the
      lens argmax matches the final argmax and never flips again — the depth at
      which the answer is effectively decided, a per-batch-mean and a 10-bin
      per-sample histogram); the per-layer mean top-1 confidence and lens
      entropy (the readout sharpens with depth); and the per-layer
      `KL(p_L || p_final)` curve (monotone decrease = the residual stream
      incrementally refining toward the final answer — the headline logit-lens
      picture). Layers whose flat size does NOT match the head input are
      explicitly listed as SKIPPED (the honest constraint: the classic lens
      needs width-compatibility), with an optional `Project` flag reusing the
      deterministic random-projection trick from [[LinearProbeReport]] to force
      a fit and a note that projected lenses are heuristic. Built-in correctness
      checks: applying the lens AT `HeadStartIdx` reproduces `p_final` exactly
      (agreement 1.0, KL 0) since no recompute substitution happens there, and a
      single-layer head degenerates to the trivial "everything resolves at the
      last layer" profile. **Distinct from** [[LinearProbeReport]] (which FITS a
      fresh ridge probe per layer via a closed-form solve and reports what a NEW
      linear classifier COULD extract — the lens fits NOTHING and reuses the
      model's OWN trained head, so it measures the model's self-belief, not the
      layer's linear decodability), from `PredictionDepthReport` (k-NN vote
      against a labelled support set — a non-parametric neighbour vote, not the
      model's own readout), from `FeatureSeparabilityReport` (label-aware
      cluster geometry, no readout at all), and from `ActivationPatchingReport`
      (causal cross-input activation swaps, not a same-input depth-wise readout).
      Follows the [[introspection-report-pattern]]: declaration + impl in
      neuralnetwork.pas, an `examples/LogitLens/` demo on a small classifier
      whose body keeps a constant width into the head (so most layers are
      lens-compatible) contrasting fresh-init (agreement stays near chance until
      the very last layer, flat KL) vs trained (agreement climbs with depth, KL
      falls monotonically, crystallization depth moves earlier) in one run, and a
      smoke test in tests/ (non-empty report, expected header, nil-NN graceful
      return, plus the lens-at-HeadStartIdx-reproduces-final agreement/KL==0
      assertion). Pairs with [[WeightSpectrumReport]] / the grokking experiment
      to watch the crystallization depth shift at a representational transition.
- [ ] MagnitudePruningReport follow-up (now landed): the report sweeps a FIXED
      sparsity menu `{0,10,...,90,95,99}%`. Add a "find-the-knee" refinement that
      bisects between the last surviving and first failing sparsity to report the
      knee to ~1% resolution instead of the 10%-grid step. ~20 lines on top of the
      landed sweep; the curve already brackets the knee.
- [ ] MagnitudePruningReport follow-up: this is the no-retrain precursor to the
      open "Lottery-ticket"-flavored experiment — wire the two together so the
      knee found here seeds the prune level, then RETRAIN from the original init
      and chart whether the pruned-then-retrained net recovers the baseline
      accuracy (the lottery-ticket claim). The report already snapshots/restores
      the unpruned weights, so the retrain path is the only new piece.
- [ ] ActivationPatchingReport follow-up (now landed): the report and example
      shipped, but a KEY finding emerged — on a strictly FEEDFORWARD stack,
      whole-layer patching + downstream recompute lands on the clean-class
      manifold at EVERY layer, so `r_L ≈ 1` is flat and nothing localises. The
      landed example works around this with a BRANCHED net (a raw-input skip
      fused by `Concat`) so the trace is graded by construction (main-branch
      patches recover ~0.04, recovery jumps to 1.0 at the fusion layer). The
      genuine follow-up is finer granularity that DOES localise on a plain
      feedforward net: per-NEURON / per-CHANNEL activation patching (restore a
      single channel's clean activation, not the whole layer) and/or the
      "denoising" direction (patch a CLEAN activation into a CORRUPT run vs the
      reverse). Add a `Granularity` flag (layer | channel) on top of the landed
      whole-layer path.
- [ ] IntrinsicDimensionReport follow-up (now landed): the PCA participation
      ratio under-counts a known `k`-dim RANDOM subspace (lands ~2.4 for k=3,
      since PR equals `k` only when the `k` eigenvalues are EQUAL); TwoNN gives
      the cleaner ~k. The smoke test bands `PCA_ID` loosely as a result. Worth a
      doc note (or an equal-variance subspace generator in the example so the
      PCA estimate also reads ~k), and consider reporting the spectral
      `effective rank exp(entropy(lambda))` alongside PR as a less variance-skewed
      linear-ID estimate.
- [ ] IntrinsicDimensionReport follow-up: a training-trajectory variant that
      calls the report every N epochs on a fixed probe set and charts the
      final-layer ID dropping over training — a single-number window into
      representation compression. Pairs with the open grokking / lottery-ticket
      experiments ([[WeightSpectrumReport]]) and mirrors the open
      FeatureSeparabilityReport training-trajectory follow-up.
- [ ] WeightSpectralTailReport follow-up: the spec's 3-way example (fresh /
      well-trained / over-fit nets ranked by held-out accuracy, validating
      label-free model selection) was simplified to a fresh-vs-trained contrast
      at landing; the accuracy-ranking demo is still open.
- [ ] RepresentationSimilarityReport follow-up: add an RBF-kernel CKA mode
      alongside the landed linear-CKA one (Gaussian Gram `K_ij =
      exp(-||x_i - x_j||^2 / (2*sigma^2))` with sigma a median-distance
      heuristic, then the same centered HSIC ratio). RBF-CKA catches
      non-linear representational similarity the linear version misses;
      gate behind a kernel selector so linear stays the default. Self-CKA
      diagonal must still read 1.0.
- [ ] TopLogitMarginReport follow-up: the shipped `examples/MarginReport/`
      net ends in a `TNNetSoftMax`, so its "logits" are post-softmax
      probabilities and the margin lands in `[0, 1]`. Add a second run (or a
      sibling example) with a raw-logit `TNNetFullConnectLinear` head so the
      unbounded-margin case is also pinned, and document the interpretation
      difference in the README.
- [ ] Shared report-smoke-test helper for the `TNNet.*Report` family. The
      per-report smoke tests (TopLogitMargin / NeuronCorrelation /
      LayerSensitivity / DeadNeuron / WeightSpectrum / ...) all repeat the
      same three assertions: report string non-empty, contains an expected
      header substring, and a nil-NN call returns gracefully. Capture as
      `AssertReportSmoke(reportFn, expectedHeader)` in
      tests/TestNeuralLayersExtra.pas so new report tasks are a one-liner.
### Test-time augmentation evaluator
- [ ] (TTAReport follow-up) the shipped report runs on a single synthetic
      probe set; a natural next step is the spec's second run on a model
      trained WITH `TNNetRandomFlipX` augmentation, to show TTA gains shrink
      when the invariance is already learned. given a trained classifier, a validation set,
      and a configurable list of input-side transforms (default menu reuses
      the existing in-tree augmentations: identity, `TNNetFlipX`,
      `TNNetFlipY`, `TNNetReverseChannels`, and a 1-pixel `Roll(X=+1)`),
      run a forward pass per transform, average the resulting logits (and,
      optionally, the post-softmax probabilities — both modes selectable via
      a flag so the linear-vs-geometric-mean question is empirically
      checkable), and report:
      (a) baseline top-1 accuracy on the untransformed inputs,
      (b) per-transform top-1 accuracy (each transform applied alone — a
          built-in correctness check for the augmentation; a healthy model
          shouldn't lose much accuracy under any single near-invariant
          transform),
      (c) full-ensemble TTA top-1 accuracy (all transforms averaged
          together) and the delta vs baseline,
      (d) per-class accuracy delta so classes that *lose* under TTA (a
          sign of a non-equivariant decision boundary for that class) are
          visible,
      (e) per-sample agreement rate `mean(argmax(avg_logits) ==
          argmax(baseline_logits))` — high agreement + small accuracy lift
          means TTA mostly confirms existing decisions; low agreement +
          large lift means TTA is genuinely flipping borderline samples,
      (f) a one-line verdict: "TTA helps" / "TTA neutral" / "TTA hurts"
          based on a configurable threshold.
      Pure forward-only — no training-time changes, no backward pass.
      Distinct from [[EquivarianceReport]] (measures how *output* reacts
      to transforms in isolation, without using a label or computing
      accuracy — answers "is the model invariant?" not "does averaging
      under transforms improve val accuracy?"), from [[SaliencyReport]]
      (per-sample input attribution, not aggregate accuracy lift), and
      from the calibration / margin-report tools (those summarise
      confidence quality on the untransformed set, no ensembling). The
      output is the natural input for any future "should we ship TTA at
      inference?" decision — you need to know which transforms actually
      help before paying their inference cost. Companion
      `examples/TestTimeAugmentation/` runs it on the SimpleImageClassifier
      CIFAR baseline so the per-transform table and ensemble delta can be
      eyeballed; the example also runs against a model trained *with*
      `TNNetRandomFlipX` augmentation so reviewers can see the expected
      pattern (TTA gains shrink when the model has already learned the
      invariance during training — TTA and train-time augmentation are
      substitutes, not complements).

### Adversarial robustness
- [ ] AdversarialRobustnessReport follow-up: add the optional
      `eps,accuracy` CSV side-output (skipped in the initial landing as
      "optional") so the degradation curve can be plotted outside the
      terminal. ~10 lines mirroring the CSV side-output already in
      DecisionBoundaryReport.
- [ ] AdversarialRobustnessReport follow-up: add a multi-step PGD
      (projected gradient descent) attack mode alongside single-step FGSM —
      iterate `x <- clip(x + alpha*sign(grad), x0 +/- eps)` for K steps. PGD
      is the standard stronger baseline; the report's accuracy-vs-eps curve
      should drop faster under PGD than FGSM at matched eps, which is itself
      a built-in sanity check. Gate behind a `Steps` parameter (Steps=1 ==
      today's FGSM).

### Parameter importance (continual learning / pruning)
- [ ] EWC two-task experiment building on the landed
      TNNet.FisherImportanceReport: train on task A, snapshot the diagonal
      Fisher, then train on task B with an L2 penalty pulling high-Fisher
      params back toward their task-A values; chart task-A retention with and
      without the penalty.
