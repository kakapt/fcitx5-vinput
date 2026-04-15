#include "vad_trimmer.h"

#include <sherpa-onnx/c-api/c-api.h>

#include <algorithm>
#include <cstdio>

VadTrimmer::VadTrimmer() = default;

VadTrimmer::~VadTrimmer() { Shutdown(); }

bool VadTrimmer::Init(const std::string &model_path, int sample_rate,
                      const std::string &provider, std::string *error) {
  if (vad_) return true;

  SherpaOnnxVadModelConfig config = {};
  config.silero_vad.model = model_path.c_str();
  config.silero_vad.threshold = 0.5f;
  config.silero_vad.min_silence_duration = 0.5f;
  config.silero_vad.min_speech_duration = 0.25f;
  config.silero_vad.window_size = 512;
  config.silero_vad.max_speech_duration = 0.0f;
  config.sample_rate = sample_rate;
  config.num_threads = 1;
  config.provider = provider.c_str();
  config.debug = 0;

  vad_ = SherpaOnnxCreateVoiceActivityDetector(&config, 30.0f);
  if (!vad_) {
    if (error) {
      *error = "failed to create VAD from '" + model_path + "'";
    }
    return false;
  }

  sample_rate_ = sample_rate;
  fprintf(stderr, "vinput: VAD initialized from '%s'\n", model_path.c_str());
  return true;
}

std::vector<float> VadTrimmer::Trim(const std::vector<float> &samples,
                                    int /*sample_rate*/) {
  if (!vad_ || samples.empty()) return samples;

  SherpaOnnxVoiceActivityDetectorReset(vad_);

  // Feed audio in window_size chunks
  const int window_size = 512;
  const int n = static_cast<int>(samples.size());
  int offset = 0;
  for (; offset + window_size <= n; offset += window_size) {
    SherpaOnnxVoiceActivityDetectorAcceptWaveform(vad_, samples.data() + offset,
                                                  window_size);
  }
  if (offset < n) {
    std::vector<float> padded_tail(window_size, 0.0f);
    const int remaining = n - offset;
    for (int i = 0; i < remaining; ++i) {
      padded_tail[i] = samples[offset + i];
    }
    SherpaOnnxVoiceActivityDetectorAcceptWaveform(vad_, padded_tail.data(),
                                                  window_size);
  }
  SherpaOnnxVoiceActivityDetectorFlush(vad_);

  // Collect all speech segments with padding from original audio
  constexpr int kPaddingSamples = 3200;  // 200ms @ 16kHz
  std::vector<float> result;
  while (!SherpaOnnxVoiceActivityDetectorEmpty(vad_)) {
    const SherpaOnnxSpeechSegment *seg =
        SherpaOnnxVoiceActivityDetectorFront(vad_);
    if (seg && seg->n > 0) {
      int start = std::max(0, static_cast<int>(seg->start) - kPaddingSamples);
      int end = std::min(n, static_cast<int>(seg->start) + static_cast<int>(seg->n) + kPaddingSamples);
      result.insert(result.end(), samples.begin() + start,
                    samples.begin() + end);
    }
    if (seg) {
      SherpaOnnxDestroySpeechSegment(seg);
    }
    SherpaOnnxVoiceActivityDetectorPop(vad_);
  }

  if (result.empty()) {
    fprintf(stderr, "vinput: VAD found no speech, returning original audio\n");
    return samples;
  }

  fprintf(stderr, "vinput: VAD trimmed %d -> %zu samples\n", n, result.size());
  return result;
}

bool VadTrimmer::Available() const { return vad_ != nullptr; }

void VadTrimmer::Shutdown() {
  if (vad_) {
    SherpaOnnxDestroyVoiceActivityDetector(vad_);
    vad_ = nullptr;
  }
}
