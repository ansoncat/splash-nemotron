#pragma once

#include "Model.hpp"
#include "StateLayout.hpp"
#include "WeightStore.hpp"
#include "ops/DraftAttention.hpp"
#include "ops/DraftSelector.hpp"
#include "ops/LiLiCorr.hpp"
#include "ops/ExecutionPlans.hpp"
#include "ops/Linear.hpp"
#include "ops/Normalization.hpp"

#include <cstdint>
#include <array>
#include <optional>
#include <memory>
#include <span>
#include <string_view>
#include <vector>

namespace splash::model {

struct DFlashDraftRingLayer final {
  // K is [head][ring_position][dimension].
  metal::MetalBuffer keys;
  // V is [head][dimension][ring_position].
  metal::MetalBuffer values;
  // A LiLiCorr draft's anchor (DraftStateLayout::anchorBytes), on its first
  // layer only.
  metal::MetalBuffer anchor;
};

// A lane's draft rings: every draft layer's keys and values of the last
// SPLASH_DRAFT_SLIDING_WINDOW positions, which its decode attends to. Cached
// states keep their context window (DFlashContextWindow) instead.
class DFlashDraftRing final {
public:
  DFlashDraftRing(metal::MetalBackend &backend,
                  std::shared_ptr<StateAllocationTracker> tracker,
                  DraftStateLayout layout,
                  std::string_view label);
  ~DFlashDraftRing();
  DFlashDraftRing(const DFlashDraftRing &) = delete;
  DFlashDraftRing &operator=(const DFlashDraftRing &) = delete;

  [[nodiscard]] const std::vector<DFlashDraftRingLayer> &layers() const noexcept {
    return layers_;
  }

private:
  std::shared_ptr<StateAllocationTracker> tracker_;
  std::vector<DFlashDraftRingLayer> layers_;
  uint64_t actualAllocatedBytes_ = 0;
};

// The context window of a lane or a cached state: the context rows the
// rings' keys and values are computed from (DraftStateLayout::windowBytes),
// which a cached state keeps in place of the rings.
class DFlashContextWindow final {
public:
  DFlashContextWindow(metal::MetalBackend &backend,
                      std::shared_ptr<StateAllocationTracker> tracker,
                      DraftStateLayout layout, std::string_view label);
  ~DFlashContextWindow();
  DFlashContextWindow(const DFlashContextWindow &) = delete;
  DFlashContextWindow &operator=(const DFlashContextWindow &) = delete;

  [[nodiscard]] const metal::MetalBuffer &buffer() const noexcept { return buffer_; }

private:
  std::shared_ptr<StateAllocationTracker> tracker_;
  metal::MetalBuffer buffer_;
  uint64_t actualAllocatedBytes_ = 0;
};

// The dimensions of a DFlash2 draft, as its checkpoint's config.json gives
// them (ModelDescriptor.mm readDraftLayout): every draft's attention widths
// and selector are those the kernels are built for; its layers, intermediate
// size, rotary base and the target layers it reads are its own, and its
// hidden size and vocabulary its target's.
struct DFlashDraftLayout final {
  uint32_t layers = 0;
  uint32_t hiddenSize = 0;
  uint32_t vocabularySize = 0;
  uint32_t dynamicSize = 0;
  uint32_t qkvSize = 0;
  uint32_t attentionSize = 0;
  uint32_t intermediateSize = 0;
  uint32_t attentionHeadDimension = 0;
  float rotaryTheta = 0.0F;
  uint32_t selectorRank = 0;
  uint32_t kvHeads = 0;
  // The positions a query row sees (sliding_window): the ring's window, or
  // 1024 for a LiLiCorr draft, whose attention also has a sink logit per
  // query head (attention_sink_bias).
  uint32_t slidingWindow = SPLASH_DRAFT_SLIDING_WINDOW;
  bool attentionSinks = false;
  // A LiLiCorr draft (Bolt's): its selector is a small network over each
  // position's eight best candidates (LiLiCorrWeights) instead of codebooks.
  bool lilicorr = false;
  // The target layers whose output rows the draft reads, ascending: the
  // first targetLayerCount of targetLayers, targetHiddenSize() values a row.
  std::array<uint32_t, ExecutionLimits::maximumDraftTargetLayers> targetLayers{};
  uint32_t targetLayerCount = 0;

  // A model without a draft (Nemotron-H) has the empty layout: its runtime
  // verifies only each lane's anchor row, and nothing reads or writes the
  // draft's state.
  [[nodiscard]] constexpr bool present() const noexcept { return layers != 0; }
  [[nodiscard]] constexpr DraftStateLayout stateLayout() const noexcept {
    if (!present()) return {};
    return {layers, kvHeads, attentionHeadDimension, hiddenSize, lilicorr ? hiddenSize : 0};
  }
  [[nodiscard]] constexpr std::span<const uint32_t> targetLayerIds() const noexcept {
    return {targetLayers.data(), targetLayerCount};
  }
  // A row of the target rows it reads: one of hiddenSize values per layer.
  [[nodiscard]] constexpr uint32_t targetHiddenSize() const noexcept { return hiddenSize * targetLayerCount; }
  [[nodiscard]] constexpr ops::DraftAttentionShape attentionShape() const noexcept {
    return {hiddenSize, dynamicSize, qkvSize, attentionSize,
            attentionSize / attentionHeadDimension, kvHeads,
            attentionHeadDimension, slidingWindow};
  }
  // The key and value columns of the fused QKV projection, all the context
  // writers read.
  [[nodiscard]] constexpr uint32_t contextKvSize() const noexcept {
    return qkvSize - attentionSize;
  }

  bool operator==(const DFlashDraftLayout &) const = default;
};

// The layout of a DFlash2 draft of a target of `hiddenSize` and
// `vocabularySize` with `layers` (at least one) layers of `intermediateSize`
// (a positive multiple of 64), rotary base `rotaryTheta` (positive), reading
// the target's layers `targetLayers` (ascending, 1 to
// ExecutionLimits::maximumDraftTargetLayers): its attention widths and
// selector are those the kernels are built for.
[[nodiscard]] DFlashDraftLayout draftLayout(uint32_t hiddenSize, uint32_t vocabularySize, uint32_t layers,
                                            uint32_t intermediateSize, float rotaryTheta,
                                            std::span<const uint32_t> targetLayers);

struct DFlashDecodeBuffers final {
  ops::LinearScratch linearScratch{};
  std::array<metal::MetalBuffer, 2> hidden;
  metal::MetalBuffer normalized;
  metal::MetalBuffer dynamic;
  metal::MetalBuffer convolved;
  metal::MetalBuffer proposalQkv;
  metal::MetalBuffer attention;
  metal::MetalBuffer projected;
  metal::MetalBuffer residual;
  metal::MetalBuffer intermediate;
  metal::MetalBuffer finalHidden;
  metal::MetalBuffer logits;
  metal::MetalBuffer selectorHidden;
  metal::MetalBuffer queryKeys;
  metal::MetalBuffer queryValues;
  metal::MetalBuffer ropeCos;
  metal::MetalBuffer ropeSin;
  metal::MetalBuffer gateScratch;
  std::vector<std::array<metal::MetalBuffer,
                         ExecutionLimits::maximumBatchWidth>> persistentKeys;
  std::vector<std::array<metal::MetalBuffer,
                         ExecutionLimits::maximumBatchWidth>> persistentValues;
};

struct DFlashContextBuffers final {
  ops::LinearScratch linearScratch{};
  metal::MetalBuffer capturedTargetHidden;
  metal::MetalBuffer projected;
  metal::MetalBuffer hidden;
  metal::MetalBuffer contextKv;
  metal::MetalBuffer ropeCos;
  metal::MetalBuffer ropeSin;
  metal::MetalBuffer retainedCounts;
  std::vector<std::array<metal::MetalBuffer,
                         ExecutionLimits::maximumBatchWidth>> persistentKeys;
  std::vector<std::array<metal::MetalBuffer,
                         ExecutionLimits::maximumBatchWidth>> persistentValues;
  // A LiLiCorr draft's lanes' anchor rows (DFlashDraftRingLayer::anchor).
  std::array<metal::MetalBuffer, ExecutionLimits::maximumBatchWidth> anchors{};
};

struct DFlashPrefillSpan final {
  uint32_t compactRow = 0;
  uint32_t rows = 0;
  uint32_t startPosition = 0;
  std::span<const DFlashDraftRingLayer> ring;
  // The lane's context window, which keeps the span's context rows.
  metal::MetalBuffer window;
};

// Context rows of a span a prefill also stores in a cached state's context
// window: the rows below a state boundary inside the command
// (ModelBatchItem::stateCaptures), whose window the command's later rows
// overwrite in the lane's.
struct DFlashWindowCapture final {
  uint32_t compactRow = 0;
  uint32_t rows = 0;
  uint32_t startPosition = 0;
  metal::MetalBuffer window;
};

struct DFlashPrefillBuffers final {
  metal::MetalBuffer capturedTargetHidden;
  // The split partials and counters of the context projections' chunks the
  // staged tile runs (Linear::addPrefill).
  ops::LinearScratch linearScratch;
  metal::MetalBuffer projected;
  metal::MetalBuffer hidden;
  metal::MetalBuffer contextKv;
  metal::MetalBuffer ropeCos;
  metal::MetalBuffer ropeSin;
};

struct DFlashDraftLayerWeights final {
  ops::NormWeights inputNorm;
  metal::MetalBuffer attentionConvolution;
  ops::Projection attentionDynamic;
  ops::Projection qkvProjection;
  metal::MetalBuffer queryNorm;
  metal::MetalBuffer keyNorm;
  // bf16 [query heads], with attentionSinks.
  metal::MetalBuffer sinks;
  ops::Projection outputProjection;
  ops::NormWeights postAttentionNorm;
  metal::MetalBuffer mlpConvolution;
  ops::Projection mlpDynamic;
  ops::Projection gateProjection;
  ops::Projection upProjection;
  ops::Projection downProjection;
};

struct DFlashDraftWeights final {
  DFlashDraftLayout layout;
  std::vector<DFlashDraftLayerWeights> layers;
  ops::Projection contextProjection;
  ops::NormWeights hiddenNorm;
  ops::NormWeights finalNorm;
  ops::Projection selectorProjection;
  metal::MetalBuffer predecessorCodebook;
  metal::MetalBuffer successorCodebook;
  // The mask token's BF16 embedding the checkpoint ships, or none
  // (kDraftMaskEmbedding).
  metal::MetalBuffer maskEmbedding;
  // A LiLiCorr draft's selector, in place of the projection and codebooks.
  std::optional<ops::LiLiCorrWeights> lilicorr;
  std::vector<WeightFileRecord> files;
  uint64_t actualAllocatedBytes = 0;
};

class DraftCheckpointLoader;

// Reads a draft from the images DraftCheckpointLoader writes from a DFlash2
// checkpoint.
[[nodiscard]] DFlashDraftWeights
loadDFlashDraftWeights(metal::MetalBackend &backend, DraftCheckpointLoader &files,
                       DFlashDraftLayout layout);

// Builds the draft layer graph and its proposal selection
// (ops::DraftSelector) from batch buffers and persistent context; the
// target's sampling and acceptance policy remain outside the model.
class DFlashDraft final {
public:
  DFlashDraft(const DFlashDraftWeights &weights, metal::MetalBackend &backend,
               const ops::ExecutionPlans &operators);

  void addContextPrefill(metal::CommandGraph &graph,
                         DFlashPrefillBuffers buffers, uint32_t rows,
                         std::span<const DFlashPrefillSpan> spans,
                         std::span<const DFlashWindowCapture> windowCaptures) const;
  // Computes the rings' keys and values of `rows` positions from
  // startPosition on again from the context window they were kept in, as
  // addContextPrefill writes them from their context rows. The rows pass
  // through the context buffers, and the RoPE tables must hold the rows'
  // positions.
  void addContextRebuild(metal::CommandGraph &graph,
                         DFlashPrefillBuffers buffers,
                         const metal::MetalBuffer &window,
                         std::span<const DFlashDraftRingLayer> ring,
                         uint32_t rows, uint32_t startPosition) const;

  // Lanes of storage the draft's own projections bind in a decode step or
  // context commit of `lanes` lanes (ops::Linear::decodeStorageRows).
  [[nodiscard]] uint32_t decodeStorageLanes(uint32_t lanes) const;
  void addDecode(metal::CommandGraph &graph, DFlashDecodeBuffers buffers,
                 const ops::Projection &vocabularyProjection,
                 std::span<const uint32_t> cacheLengths) const;
  // A LiLiCorr draft's selection also reads addDecode's final hidden rows,
  // the target's token table and each lane's anchor row (ops::LiLiCorr).
  void addSelection(metal::CommandGraph &graph,
                    const ops::DraftSelectorBuffers &buffers,
                    std::span<const uint32_t> anchors,
                    std::span<const ops::SamplingPolicy> policies,
                    const metal::MetalBuffer &finalHidden = {},
                    const ops::EmbeddingWeights *tokenEmbedding = nullptr,
                    std::span<const metal::MetalBuffer> anchorRows = {}) const;
  [[nodiscard]] bool lilicorr() const noexcept { return weights_.lilicorr.has_value(); }
  // The bytes of a LiLiCorr selector's scratch (allocateLiLiCorr) for
  // `weights`, each buffer's in whole host pages; zero without one. The
  // memory plan charges them to shared decode.
  [[nodiscard]] static uint64_t liLiCorrBytes(const DFlashDraftWeights &weights, const ops::ExecutionPlans &operators);
  // What allocateLiLiCorr allocated, as Metal counts it.
  [[nodiscard]] uint64_t allocatedLiLiCorrBytes() const noexcept;
  // Sets each of `lanes` lanes' mask rows of the draft input `rows` (all but
  // its anchor's, row 0 of its draftQueryRows) to the mask embedding the
  // checkpoint ships; without one they keep the target table's row.
  void addMaskRows(metal::CommandGraph &graph, metal::MetalBuffer rows, uint32_t lanes) const;

  void addContextCommit(metal::CommandGraph &graph,
                        DFlashContextBuffers buffers,
                        std::span<const uint32_t> startPositions) const;

private:
  // Each layer's context keys and values of the `rows` context rows in the
  // buffers' hidden rows, written to the spans' rings.
  void addContextKv(metal::CommandGraph &graph, const DFlashPrefillBuffers &buffers,
                    uint32_t rows, std::span<const DFlashPrefillSpan> spans) const;
  void allocateLiLiCorr();

  const DFlashDraftWeights &weights_;
  metal::MetalBackend &backend_;
  const ops::ExecutionPlans &operators_;
  ops::DraftSelector selector_;
  // Each layer's key and value rows of its QKV projection, views of its
  // planes, which the context writers project with.
  std::vector<ops::Projection> contextKvProjections_;
  // A LiLiCorr selector's scratch for the widest batch.
  std::optional<ops::LiLiCorrScratch> lilicorr_;
};

} // namespace splash::model
