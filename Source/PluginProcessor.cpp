#include "PluginProcessor.h"
#include "PluginEditor.h"

// The wall at the top of the Compression knob. Everything here is multiplied by
// RVoxCompressor::slamForAmount(), which is exactly zero at knob 24 and below.
static constexpr float SLAM_REL_MS        = 25.0f;   // both release times converge here
static constexpr float SLAM_TARGET_DB     = -11.0f;  // detector-domain level the wall sits at
static constexpr float SLAM_MAX_DRIVE_DB  =  36.0f;  // most the drive may lift a quiet source
// How fast AUTO's rubber band pulls the knob back to the sweet spot: gentle
// for a small correction, hard when it has been dragged far out.
static constexpr float MAKEUP_SEC = 5.0f;
static constexpr float RIDE_RETURN_NEAR_SEC = 0.50f;   // a couple of units out
static constexpr float RIDE_RETURN_FAR_SEC  = 0.20f;   // dragged 20+ units out

static constexpr float SLAM_MAKEUP_MAX_DB =  60.0f;

SmartCompProcessor::SmartCompProcessor()
    : AudioProcessor(BusesProperties()
                     .withInput("Input", juce::AudioChannelSet::stereo(), true)
                     .withOutput("Output", juce::AudioChannelSet::stereo(), true)),
      apvts(*this, &undoManager, "Parameters", createParameterLayout())
{
}

SmartCompProcessor::~SmartCompProcessor() {}

juce::AudioProcessorValueTreeState::ParameterLayout SmartCompProcessor::createParameterLayout()
{
    std::vector<std::unique_ptr<juce::RangedAudioParameter>> params;

    // Only parameters the processor actually reads. Eleven others used to be
    // registered here — clipmode, lookahead, boost, attackMs, relFastMs,
    // relSlowMs, kneeW, grRange, oversample, ratioMult, transProtect — none of
    // which were ever read: processBlock hardcoded their effects. They still
    // showed up in the host's automation list and got saved into sessions, so a
    // user could automate a control that did nothing. "clip" went later: the
    // saturation was too subtle to justify a control, and a dedicated limiter
    // plugin (SmartLim) covers that territory properly.
    params.push_back(std::make_unique<juce::AudioParameterBool>(
        juce::ParameterID("bypass", 1), "Bypass", false));
    params.push_back(std::make_unique<juce::AudioParameterFloat>(
        juce::ParameterID("comp", 1), "Compression",
        juce::NormalisableRange<float>(0.0f, 36.0f, 0.1f), 0.0f));
    params.push_back(std::make_unique<juce::AudioParameterFloat>(
        juce::ParameterID("gain", 1), "Out Gain",
        juce::NormalisableRange<float>(-24.0f, 12.0f, 0.1f), 0.0f));
    params.push_back(std::make_unique<juce::AudioParameterFloat>(
        juce::ParameterID("schpf", 1), "SC HP Filter",
        juce::NormalisableRange<float>(0.0f, 400.0f, 1.0f, 0.4f), 0.0f));
    params.push_back(std::make_unique<juce::AudioParameterFloat>(
        juce::ParameterID("mix", 1), "Mix",
        juce::NormalisableRange<float>(0.0f, 100.0f, 1.0f), 100.0f));
    params.push_back(std::make_unique<juce::AudioParameterFloat>(
        juce::ParameterID("gate", 1), "Gate",
        juce::NormalisableRange<float>(-80.0f, -20.0f, 0.1f), -80.0f));
    params.push_back(std::make_unique<juce::AudioParameterFloat>(
        juce::ParameterID("inTrim", 1), "In Trim",
        juce::NormalisableRange<float>(-12.0f, 12.0f, 0.1f), 0.0f));

    return { params.begin(), params.end() };
}

void SmartCompProcessor::prepareToPlay(double sampleRate, int samplesPerBlock)
{
    currentSampleRate = sampleRate;
    // The compressor is fed the 2x oversampled block, so it must be prepared at
    // that rate. It was being given the host rate, which halved every time
    // constant (50 ms RMS window ran as 25 ms, releases at half their labels) and
    // put every detector filter an octave high — the SC HP Filter knob read
    // 100 Hz and delivered 200 Hz. Latency accounting already accounted for the
    // 2x domain; only the coefficients were missed.
    compressor.prepare(sampleRate * compOSFactor, samplesPerBlock * compOSFactor);
    limiter.prepare(sampleRate, samplesPerBlock);   // limiter runs at base rate

    // Integer latency: without this getLatencyInSamples() returns a fractional
    // group delay which the (int) cast below silently truncated, leaving the
    // dry/wet mix misaligned by a fraction of a sample. JUCE inserts the
    // fractional part itself when asked to.
    compOS.setUsingIntegerLatency(true);
    compOS.initProcessing((size_t)samplesPerBlock);
    compOS.reset();

    // Wet path latency — every stage that delays the signal, so the dry/wet mix
    // and the host's compensation both line up.
    totalWetLatency = compressor.getLatencySamples() / compOSFactor
                    + (int)compOS.getLatencyInSamples()
                    + limiter.getLatencySamples();
    setLatencySamples(totalWetLatency);

    // Dry delay for latency-compensated mix
    preparedBlockSize = samplesPerBlock;
    int delaySize = totalWetLatency + samplesPerBlock + 16;
    dryDelayL.assign(delaySize, 0.0f);
    dryDelayR.assign(delaySize, 0.0f);
    dryDelayWritePos = 0;
    bypassDelayL.assign(delaySize, 0.0f);
    bypassDelayR.assign(delaySize, 0.0f);
    bypassDelayWritePos = 0;
    // Crossfade scratch, preallocated: it used to be a 2048-sample stack array,
    // so on a larger block the fade simply stopped after 2048 samples and the
    // output jumped.
    fadeFromL.assign((size_t)samplesPerBlock, 0.0f);
    fadeFromR.assign((size_t)samplesPerBlock, 0.0f);
    monoScratch.assign((size_t)samplesPerBlock, 0.0f);

    // Ramp and filter state: initialised at construction but previously never
    // re-initialised here, so a re-prepare replayed stale gain and DC state.
    prevTrimLin = 1.0f;
    prevMakeupLin = 1.0f;
    prevOffsetLin = 1.0f;
    prevMixWet = 1.0f;
    prevOutTrimLin = 1.0f;
    matchResidualDB = 0.0f;
    dcBlockL = dcBlockR = dcPrevInL = dcPrevInR = 0.0f;
    prevBypassed = false;

    smoothedInMS = 0.0f;
    smoothedOutMS = 0.0f;
    slowInMS = 0.0f; slowOutMS = 0.0f; slowPredictedDB = 0.0f; slowPredictedPrimed = false;
    smoothedInLUFS = 0.0f;
    smoothedOutLUFS = 0.0f;
    smoothedPeakDB = -60.0f;
    smoothedRMSDB = -60.0f;
    smoothedCrestDB = 12.0f;
    analysisBlockCount = 0;
    dcBlockCoeff = 1.0f - (float)(2.0 * juce::MathConstants<double>::pi * 5.0 / sampleRate); // ~5Hz HPF
    kShelfIn = {}; kHPIn = {}; kShelfOut = {}; kHPOut = {};
    computeKWeightingCoeffs(sampleRate);


    rideSmoothedComp = 0.0f;
    rideSmoothedInit = false;
    rideTargetComp.store(0.0f);
}

void SmartCompProcessor::releaseResources()
{
    compressor.reset(); limiter.reset();
    compOS.reset();
}

bool SmartCompProcessor::isBusesLayoutSupported(const BusesLayout& layouts) const
{
    const auto in  = layouts.getMainInputChannelSet();
    const auto out = layouts.getMainOutputChannelSet();
    if (in.isDisabled() || out.isDisabled())
        return false;
    // Mono is allowed now. Stereo-only meant Logic would not offer the AU on
    // mono tracks, which is the primary case for a vocal compressor.
    const bool inOK  = in  == juce::AudioChannelSet::mono() || in  == juce::AudioChannelSet::stereo();
    const bool outOK = out == juce::AudioChannelSet::mono() || out == juce::AudioChannelSet::stereo();
    // Never fewer output channels than input
    return inOK && outOK && out.size() >= in.size();
}

void SmartCompProcessor::processBlock(juce::AudioBuffer<float>& buffer, juce::MidiBuffer&)
{
    juce::ScopedNoDenormals noDenormals;
    if (buffer.getNumChannels() < 1) return;

    // Mono in, stereo out: mirror channel 0 rather than leaving channel 1 silent.
    // The stock "clear the extra outputs" idiom would leave the detector summing
    // signal against silence and reading 6 dB low.
    if (getTotalNumInputChannels() < 2 && buffer.getNumChannels() >= 2)
        buffer.copyFrom(1, 0, buffer, 0, 0, buffer.getNumSamples());
    else
        for (auto i = getTotalNumInputChannels(); i < getTotalNumOutputChannels(); ++i)
            buffer.clear(i, 0, buffer.getNumSamples());

    int numSamples = buffer.getNumSamples();
    if (numSamples == 0) return;
    // Everything downstream is sized for the block size prepareToPlay was given.
    // A host handing us more would overrun the oversamplers' internal buffers,
    // which JUCE only guards with a jassert that compiles out in Release.
    numSamples = juce::jmin(numSamples, preparedBlockSize);
    // The chain is stereo throughout. On a mono track we mirror the single
    // channel into scratch, process as dual mono, and hand back channel 0 —
    // cheaper and far less error-prone than making every stage channel-count
    // aware, and the result is identical because both sides see the same input.
    const bool isMono = buffer.getNumChannels() < 2;
    float* left  = buffer.getWritePointer(0);
    float* right = nullptr;
    if (isMono) {
        if ((int)monoScratch.size() < numSamples) return;   // not prepared yet
        std::copy(left, left + numSamples, monoScratch.begin());
        right = monoScratch.data();
    } else {
        right = buffer.getWritePointer(1);
    }

    // Sanitize the input before anything recursive touches it. A single NaN or
    // Inf sample would otherwise poison the envelope followers, DC blocker and
    // LUFS accumulators permanently — they are pure IIR state with no way back,
    // so the plugin would stay silent until it is reloaded. The clamp is far
    // above any real signal (1e6 ~ +120 dBFS) and only exists to keep squares
    // and makeup gain inside float range.
    for (int i = 0; i < numSamples; ++i) {
        if (! std::isfinite(left[i]))  left[i]  = 0.0f;
        if (! std::isfinite(right[i])) right[i] = 0.0f;
        left[i]  = juce::jlimit(-1.0e6f, 1.0e6f, left[i]);
        right[i] = juce::jlimit(-1.0e6f, 1.0e6f, right[i]);
    }

    bool bypassed = apvts.getRawParameterValue("bypass")->load() > 0.5f;

    // Raw input into the bypass delay line, always, so the bypass path and the
    // crossfade always have latency-aligned material available regardless of
    // which state we were in last block.
    {
        const int bdSize = (int)bypassDelayL.size();
        for (int i = 0; i < numSamples; ++i) {
            bypassDelayL[(size_t)bypassDelayWritePos] = left[i];
            bypassDelayR[(size_t)bypassDelayWritePos] = right[i];
            bypassDelayWritePos = (bypassDelayWritePos + 1) % bdSize;
        }
    }

    // Crossfade source: the delayed raw input, i.e. exactly what the bypassed
    // path outputs. It used to be the *undelayed* input, so the fade mixed two
    // signals 67 samples apart — a comb sweep — and then ended on the undelayed
    // one, so the next block jumped back by that much. A click either way.
    const int ns = juce::jmin(numSamples, (int)fadeFromL.size());
    if (bypassed != prevBypassed) {
        const int bdSize = (int)bypassDelayL.size();
        const int base = (bypassDelayWritePos - numSamples + bdSize * 2) % bdSize;
        for (int i = 0; i < ns; ++i) {
            int rp = (base + i - totalWetLatency + bdSize * 2) % bdSize;
            fadeFromL[(size_t)i] = bypassDelayL[(size_t)rp];
            fadeFromR[(size_t)i] = bypassDelayR[(size_t)rp];
        }
        // Clear stale oversampler state so re-engaging does not dump it into
        // the signal.
        compOS.reset();
    }

    // Knob 0-36, negated for processing. There used to be a 29/36 remap here
    // while the compressor divided by 36 internally, so the knob only ever
    // reached 80% of the designed range: max ratio came out at 10:1 instead of
    // 15:1. With the auto threshold the remap has no purpose either way.
    float compDB   = -apvts.getRawParameterValue("comp")->load();
    // Out Gain is a true output level now, not the limiter ceiling. Using it as
    // the ceiling meant turning it down made the signal quieter *and* flatter
    // (12.8 dB of limiting at 0, 24.8 dB at -12), so there was no way out of
    // permanent limiting. The ceiling is fixed just below full scale instead.
    float outTrimDB = apvts.getRawParameterValue("gain")->load();
    static constexpr float CEILING_DB = -0.3f;
    float scHpFreq = apvts.getRawParameterValue("schpf")->load();
    float mixAmt   = apvts.getRawParameterValue("mix")->load() / 100.0f;
    float inTrimDB = apvts.getRawParameterValue("inTrim")->load();

    // Input metering + K-weighted LUFS
    float inPL = 0, inPR = 0, inKSumSq = 0;
    for (int i = 0; i < numSamples; ++i) {
        inPL = std::max(inPL, std::abs(left[i]));
        inPR = std::max(inPR, std::abs(right[i]));
        float mono = (left[i] + right[i]) * 0.5f;
        // K-weight the mono signal
        float kFiltered = applyBiquad(mono, kShelfIn, kShelfCoeffs);
        kFiltered = applyBiquad(kFiltered, kHPIn, kHPCoeffs);
        inKSumSq += kFiltered * kFiltered;
    }
    inputPeakL.store(inPL); inputPeakR.store(inPR);
    // Integrate MEAN SQUARE, not amplitude. Smoothing sqrt(mean-square) under-
    // reads, and because sqrt is concave the deficit grows with inter-block level
    // variance — so it under-read the dynamic input more than the compressed
    // output, and unlike a filter-shape error that bias does not cancel between
    // the two chains. HONEST was under-matching by up to 0.66 dB, more the harder
    // the compression, which is the opposite of what the mode promises.
    float blockInMS = inKSumSq / (float)numSamples;
    // Block-size independent smoothing: ~800ms time constant (slow enough for knob changes)
    float lufsSmooth = std::exp(-(float)numSamples / (float)(currentSampleRate * 0.800));
    smoothedInMS = smoothedInMS * lufsSmooth + blockInMS * (1.0f - lufsSmooth);
    // Post-trim, because that is what the compressor is fed.
    {
        const float trimSq = std::pow(10.0f, inTrimDB / 10.0f);
        const float sm = std::exp(-(float)numSamples / (float)(currentSampleRate * MAKEUP_SEC));
        slowInMS = slowInMS * sm + blockInMS * trimSq * (1.0f - sm);
        if (! std::isfinite(slowInMS) || slowInMS < 0.0f) slowInMS = 0.0f;
    }
    if (! std::isfinite(smoothedInMS) || smoothedInMS < 0.0f) smoothedInMS = 0.0f;
    // Input is measured before In Trim, but trim is a pure gain, so scaling the
    // result is exact and avoids HONEST fighting the user's trim: pull trim down
    // and it used to try to put up to 6 dB back.
    smoothedInLUFS = std::sqrt(smoothedInMS) * std::pow(10.0f, inTrimDB / 20.0f);
    inputRMS.store(smoothedInLUFS);

    // === Signal analysis for Sweet Spot ===
    // Improved algorithm: uses input level + crest factor to compute
    // the comp knob range that produces 3-8dB GR on vocal peaks.
    // Silence-gated to avoid noise floor corrupting measurements.
    {
        float blockRMS = 0.0f;
        float blockPeak = 0.0f;
        for (int i = 0; i < numSamples; ++i) {
            float mono = std::abs((left[i] + right[i]) * 0.5f);
            blockRMS += mono * mono;
            blockPeak = std::max(blockPeak, mono);
        }
        blockRMS = std::sqrt(blockRMS / (float)numSamples);
        float rmsDB = blockRMS > 1e-6f ? 20.0f * std::log10(blockRMS) : -60.0f;
        float peakDB = blockPeak > 1e-6f ? 20.0f * std::log10(blockPeak) : -60.0f;

        // Silence gate: only analyze blocks with vocal signal (> -35dB peak)
        // Breaths (-30 to -40dB) and pauses are ignored — sweet spot stays stable
        bool isActive = peakDB > -35.0f;

        if (analysisBlockCount < 1000000) analysisBlockCount++;
        int learnBlocks = (int)(currentSampleRate * 1.0 / (double)numSamples);
        float smoothCoeff = analysisBlockCount < learnBlocks ? 0.12f : 0.03f;

        if (isActive)
        {
            // Track peak and RMS of active signal separately
            // Peak uses asymmetric smoothing: fast attack, slow release (like a meter)
            if (peakDB > smoothedPeakDB)
                smoothedPeakDB = smoothedPeakDB * 0.7f + peakDB * 0.3f; // fast rise
            else
                smoothedPeakDB = smoothedPeakDB * (1.0f - smoothCoeff * 0.5f) + peakDB * smoothCoeff * 0.5f; // slow fall

            smoothedRMSDB = smoothedRMSDB * (1.0f - smoothCoeff) + rmsDB * smoothCoeff;

            float crestDB = smoothedPeakDB - smoothedRMSDB;
            crestDB = juce::jlimit(3.0f, 30.0f, crestDB);
            smoothedCrestDB = smoothedCrestDB * (1.0f - smoothCoeff) + crestDB * smoothCoeff;
        }

        inputRMSdB.store(rmsDB);
        inputDynamicRange.store(smoothedCrestDB);
        inputPeakDBSmoothed.store(smoothedPeakDB);

        // === Compute sweet spot from signal characteristics ===
        // The comp knob maps to:
        //   threshold = -6 - (comp/36) * 30
        //   ratio = 1 + (comp/36)^2 * 9
        // We reverse-engineer: for a given target GR on peaks, what comp value?
        //
        // Strategy: find comp values where estimated GR = target
        // ssLow  = comp where GR on peaks ≈ 3dB  (entering sweet spot)
        // ssHigh = comp where GR on peaks ≈ 8dB  (leaving sweet spot)

        // The threshold is referenced to the programme level now, so distance
        // above it no longer depends on the absolute input level — only on the
        // knob's depth setting plus how far the detector's own peaks rise above
        // its average. That makes the estimate level-independent.
        //
        // This used to compare an absolute threshold against smoothedPeakDB,
        // which was wrong twice over: it used a divisor the compressor did not
        // use, and it fed a peak level into a curve the compressor drives from
        // an RMS-dominant detector. It predicted 20.6 dB of reduction where the
        // real value was 2.9 dB.
        //
        // The detector is RMS-dominant (peak blend 0.08-0.20), so it sees far
        // less crest than the waveform does; the 0.4 factor is an approximation
        // of that, not a derived constant.
        // Calibrated, not derived. With the law above now exact, this is the one
        // remaining approximation, and it was carrying the error the wrong depth
        // used to hide: measured against the real compressor on a test vocal,
        // 3 dB of peak reduction arrives at knob 8.1 and 5 dB at knob 11.4, and
        // reproducing those two points needs 8.87 dB of detector crest against
        // the 4.15 this produced. The old 8 dB ceiling would have clipped the
        // right answer even so. auto_probe's case [1b] measures both crossings,
        // so this cannot drift again unnoticed.
        float detectorCrest = juce::jlimit(2.0f, 12.0f, smoothedCrestDB * 0.855f);

        // Ask the compressor what its own law delivers instead of reproducing it
        // here. The reproduction had drifted on three counts — threshold depth
        // 30 dB against the 18 dB actually used, no slam term, and a flat knee
        // instead of the adaptive one — while its comments asserted a match on
        // all three. It over-predicted the reduction, so the search found the
        // 3 and 5 dB crossings too low on the knob and AUTO parked short of the
        // compression it advertises.
        auto estimateGR = [&](float comp) -> float {
            return RVoxCompressor::predictGainReductionDB(comp / 36.0f, detectorCrest,
                                                          compressor.userKneeWidth);
        };

        // Search for comp values that give target GR amounts
        // Uses the actual compressor transfer function, not approximations
        // 8 dB was "firm/aggressive" by normal vocal-mixing convention rather
        // than "sweet spot" — 3-5 dB on peaks is the usual gentle-to-moderate
        // range. Lowered on Frank's call after a screenshot exposed a 7.6 dB
        // reading at the coded midpoint of the old 3-8 dB band.
        float grTargetLow = 3.0f;   // entering sweet spot: gentle GR
        float grTargetHigh = 5.0f;  // leaving sweet spot: moderate GR

        // Adjust targets based on crest factor:
        // High crest (dynamic vocal): slightly higher GR targets (more headroom to compress)
        // Low crest (already compressed): lower GR targets (less room before artifacts)
        float crestScale = juce::jlimit(0.8f, 1.3f, smoothedCrestDB / 12.0f);
        grTargetLow *= crestScale;
        grTargetHigh *= crestScale;

        // Find comp value for each target via linear search (0.5 step, cheap)
        float ssLowVal = 8.0f, ssHighVal = 22.0f; // defaults
        bool foundLow = false, foundHigh = false;
        for (float c = 0.5f; c <= 36.0f; c += 0.5f) {
            float gr = estimateGR(c);
            if (!foundLow && gr >= grTargetLow) {
                ssLowVal = c;
                foundLow = true;
            }
            if (!foundHigh && gr >= grTargetHigh) {
                ssHighVal = c;
                foundHigh = true;
            }
        }
        if (!foundHigh) ssHighVal = juce::jmin(ssLowVal + 10.0f, 34.0f);

        // Ensure minimum sweet spot width (at least 4dB range on knob)
        if (ssHighVal - ssLowVal < 4.0f)
            ssHighVal = ssLowVal + 4.0f;

        // Clamp to valid range
        ssLowVal = juce::jlimit(2.0f, 30.0f, ssLowVal);
        ssHighVal = juce::jlimit(6.0f, 34.0f, ssHighVal);

        // Smooth the output to prevent jitter
        float ssSmooth = analysisBlockCount < learnBlocks ? 0.08f : 0.018f;
        sweetSpotLow.store(sweetSpotLow.load() * (1.0f - ssSmooth) + ssLowVal * ssSmooth);
        sweetSpotHigh.store(sweetSpotHigh.load() * (1.0f - ssSmooth) + ssHighVal * ssSmooth);
    }

    // === AUTO: follow the sweet-spot midpoint ===
    //
    // This computes an ABSOLUTE target in knob units, not an offset from where
    // the user left the knob. The previous version tracked
    // `offset = ssMid - userComp` and added it back, which cancels out: turning
    // the knob raised userComp and lowered the offset by the same amount, so
    // AUTO never pulled the knob back. It looked like AUTO had stopped working
    // whenever you dragged past the sweet spot, and after switching AUTO off,
    // driving into the red and switching it back on, the offset had to unwind
    // from a stale value first.
    //
    // The editor pushes this value into the real "comp" parameter each frame
    // unless the user is actively dragging, so the knob is never lying about
    // what the compressor is doing — and when you let go after dragging away,
    // it springs back.
    if (rideMode.load() && !bypassed) {
        const float ssMid = (sweetSpotLow.load() + sweetSpotHigh.load()) * 0.5f;
        const float target = juce::jlimit(0.0f, 36.0f, ssMid);

        if (! rideSmoothedInit) {
            // Seed from wherever the knob currently is, so engaging AUTO glides
            // from the user's setting instead of jumping.
            rideSmoothedComp = juce::jlimit(0.0f, 36.0f, -compDB);
            rideSmoothedInit = true;
        }

        if (compKnobDragging.load()) {
            // Pin the internal state to the live knob while the user is actively
            // moving it. Without this it kept gliding toward the sweet spot in
            // the background for the whole duration of the drag, so by release
            // time it had often already arrived — the visible "spring back" was
            // really just the editor syncing to a value that finished converging
            // silently, which read as an instant snap rather than a glide.
            rideSmoothedComp = juce::jlimit(0.0f, 36.0f, -compDB);
        } else {
            // Asymmetric: move up quickly when the material needs more
            // compression, ease back down more gently, so a breath or a pause
            // does not back the compression off.
            //
            // The downward move is a rubber band, and the tension scales with
            // how far it has been pulled. A one-pole is already fastest when it
            // is furthest from the target, but with a FIXED time constant the
            // trip always looks the same length: dragging 23 units into the red
            // took as long to come back as a 3 unit nudge, which is what made a
            // big drag feel sluggish. Scaling the time constant with the
            // distance too is what makes it read as tension rather than drift —
            // it pulls hard from far out and eases in as it arrives.
            const float direction = target - rideSmoothedComp;
            float smoothTime;
            if (direction > 0.2f)
            {
                smoothTime = 0.10f;                       // needs more comp — follow fast
            }
            else if (direction < -0.2f)
            {
                const float stretch = juce::jlimit(0.0f, 1.0f, (-direction - 2.0f) / 18.0f);
                smoothTime = RIDE_RETURN_NEAR_SEC
                           + stretch * (RIDE_RETURN_FAR_SEC - RIDE_RETURN_NEAR_SEC);
            }
            else
            {
                smoothTime = 0.15f;                       // near target — gentle
            }

            const float k = std::exp(-(float)numSamples / (currentSampleRate * smoothTime));
            rideSmoothedComp = rideSmoothedComp * k + target * (1.0f - k);
            if (! std::isfinite(rideSmoothedComp)) rideSmoothedComp = target;
        }

        rideTargetComp.store(rideSmoothedComp);
        compDB = -rideSmoothedComp;
    } else {
        rideSmoothedInit = false;
        rideTargetComp.store(0.0f);
    }

    compDB = juce::jlimit(-36.0f, 0.0f, compDB);

    // dlySize needed for dry/wet mix
    int dlySize = (int)dryDelayL.size();

    if (!bypassed)
    {
        // 0. Input Trim — per-sample interpolated to prevent zipper noise
        float trimLin = std::pow(10.0f, inTrimDB / 20.0f);
        if (std::abs(trimLin - 1.0f) > 0.0001f || std::abs(prevTrimLin - 1.0f) > 0.0001f) {
            float trimDelta = (trimLin - prevTrimLin) / (float)numSamples;
            float curTrim = prevTrimLin;
            for (int i = 0; i < numSamples; ++i) {
                curTrim += trimDelta;
                left[i] *= curTrim;
                right[i] *= curTrim;
            }
        }
        prevTrimLin = trimLin;
        // Detect input clipping after trim
        bool inClip = false;
        for (int i = 0; i < numSamples; ++i) {
            if (std::abs(left[i]) >= 1.0f || std::abs(right[i]) >= 1.0f) { inClip = true; break; }
        }
        inputClipping.store(inClip);

        // (Sidechain HPF is handled internally by the compressor's detector)

        // (Input saturation removed — causes audible distortion on sub bass)

        // Write dry signal into latency-compensated delay AFTER all pre-processing
        // This ensures dry and wet match in level, frequency content, and phase
        for (int i = 0; i < numSamples; ++i) {
            dryDelayL[dryDelayWritePos] = left[i];
            dryDelayR[dryDelayWritePos] = right[i];
            dryDelayWritePos = (dryDelayWritePos + 1) % dlySize;
        }

        // 3. Compressor — internally optimized timing (no user attack/release)
        compressor.smoothAttack = true;
        float gateThresh = apvts.getRawParameterValue("gate")->load();

        // Attack/Release driven by comp amount — like RVox, always optimal
        // Fast attack + RMS detector + lookahead = consonants preserved naturally
        float compAmt01 = juce::jlimit(0.0f, 1.0f, -compDB / 36.0f);
        float attackMs = 0.1f;  // near-instant, lookahead handles smoothing
        const float slam01 = RVoxCompressor::slamForAmount(compAmt01);
        float relFastMs = 40.0f + (1.0f - compAmt01) * 40.0f;  // 40-80ms: tighter at high comp
        float relSlowMs = 400.0f + (1.0f - compAmt01) * 600.0f;  // 400-1000ms: shorter at high comp
        // Both converge on 25 ms at the top. A long release is the intuitive
        // anti-pump move and it is wrong here: once the makeup below stops
        // putting the level back, the gain's job is to fill the troughs, not to
        // sit still. Measured breakbeat/vocal spread at knob 36 with the rest of
        // this in place: 400/40 ms -> 8.52 / 23.25, 40 ms -> 4.11 / 13.18,
        // 25 ms -> 3.33 / 10.69, 20 ms -> 2.98 / 9.69. Monotone; 25 ms is where
        // density stops being worth the distortion.
        relFastMs += slam01 * (SLAM_REL_MS - relFastMs);
        relSlowMs += slam01 * (SLAM_REL_MS - relSlowMs);
        float kneeW = 6.0f;
        compressor.setAttackTime(attackMs / 1000.0f);
        compressor.setReleaseTimes(relFastMs / 1000.0f, relSlowMs / 1000.0f);
        compressor.userKneeWidth = kneeW;
        compressor.maxGainReductionDB = 36.0f;
        compressor.ratioMultiplier = 1.0f;

        // Sidechain HPF: filters detector only, bass passes through to output
        compressor.setScHpfFreq(scHpFreq);

        // Compressor — fixed 2x oversampling for alias-free gain modulation
        {
            // The channels we actually process, not the buffer's. On a mono bus
            // `right` points at monoScratch, so an AudioBlock built from the
            // buffer handed the compressor one channel and left the other side
            // of the dual-mono chain unprocessed. Latent until now; the drive
            // below makes it audible — measured, a mono bus landed at
            // -24.47 dBFS against stereo's -10.23 at the same setting.
            float* compChans[2] = { left, right };
            juce::dsp::AudioBlock<float> block(compChans, 2, (size_t)numSamples);
            auto osBlock = compOS.processSamplesUp(block);
            int osN = (int)osBlock.getNumSamples();
            float* osL = osBlock.getChannelPointer(0);
            float* osR = osBlock.getChannelPointer(1);
            compressor.process(osL, osR, osN, compDB, gateThresh);
            compOS.processSamplesDown(block);
        }

        {
            // === NORMAL OUTPUT PATH ===

            // 4. Makeup gain — follows the gain reduction actually delivered.
            //
            // This used to be derived from the knob position instead, which did
            // not match what the compressor was doing: at Comp 8 the detector
            // produced 0 dB of reduction while makeup added +7.4 dB, so the
            // limiter downstream was already working, and from Comp 12 up it sat
            // in continuous double-digit reduction. That is what made the plugin
            // sound loud and flat regardless of setting.
            // Makeup is applied after the compressor, so it never feeds back
            // into the detector.
            // Makeup replaces the loudness the compressor actually removed,
            // measured as K-weighted energy either side of it rather than as a
            // time-average of the reduction it reported. Those are not the same
            // number on anything with pauses: energy sits exactly where the
            // reduction is largest, so a time-average under-reads it. Measured,
            // that gap made a vocal 4.5 dB quieter at knob 12 while the meter
            // reported 1.5 dB of reduction, and 7.7 dB quieter by knob 24 —
            // the knob got quieter the further it was turned up.
            //
            // The window is seconds, not the 500 ms the reduction average used.
            // At 500 ms it sits in the band where musical dynamics live and
            // cancels them; this only has to follow the setting, not the music.
            // slowOutMS is one block behind, which is immaterial at this length.
            float lossDB = (slowInMS > 1.0e-12f && slowOutMS > 1.0e-12f)
                         ? 10.0f * std::log10(slowInMS / slowOutMS) : 0.0f;
            if (! std::isfinite(lossDB)) lossDB = 0.0f;

            // Split into a part that is known and a part that must be measured.
            // The law's predicted reduction is a pure function of the knob, so
            // it moves the instant the knob does; smoothing a copy of it with
            // the same window and subtracting that leaves only the difference
            // between the prediction and what the material actually cost, which
            // is the slow part. In steady state the two cancel exactly and this
            // is still the measured loss.
            //
            // Without the split the whole makeup waited on a seconds-long
            // measurement while the compressor started reducing immediately:
            // sweeping the knob from 0 to 36 in a second dropped the level by
            // 25 dB on the way through before the makeup caught up.
            // The law's own predicted reduction, which is a pure function of the
            // knob and therefore moves the instant the knob does. Fitted against
            // what the compressor actually delivers across both test materials
            // it is good to 1.44 dB RMS, so the slow half below has very little
            // left to correct.
            //
            // A version carrying a nominal crest term was tried, on the theory
            // that the envelope rides above the programme level and the depth
            // alone under-reads the reduction. Fitting it against the measured
            // curve says otherwise: crest 0 fits to 1.44 dB, crest 9 to 7.5 dB
            // and crest 30 to 23.4 dB. Raising it did shrink the sweep dip, but
            // only by over-boosting during the move — which the dip metric
            // cannot see, because it only looks for movement AGAINST the knob.
            const float predictedDB = compressor.getStaticMakeupDB();
            {
                // Primed on the first block. Left to converge from zero it spent
                // fifteen seconds handing out a makeup that was far too large,
                // which is both wrong on load and long enough to dominate a
                // measurement that only skips three.
                const float sm = std::exp(-(float)numSamples / (float)(currentSampleRate * MAKEUP_SEC));
                if (! slowPredictedPrimed) { slowPredictedDB = predictedDB; slowPredictedPrimed = true; }
                slowPredictedDB = slowPredictedDB * sm + predictedDB * (1.0f - sm);
                if (! std::isfinite(slowPredictedDB)) slowPredictedDB = 0.0f;
            }
            float makeupDB = juce::jlimit(0.0f, 24.0f,
                                          predictedDB + (lossDB - slowPredictedDB));

            // Above knob 24 the servo is crossfaded OUT, not added to. Following
            // the delivered reduction restores the level and nothing more:
            // measured, the net gain from compressor input to plugin output was
            // -0.01 / 0.00 / +0.01 dB at knob 12 / 24 / 36, i.e. the chain was
            // unity gain by construction at every setting. That is why the
            // limiter reported exactly 0.00 dB of reduction everywhere — the
            // ceiling was unreachable rather than merely unreached. Adding a
            // drive on top of the servo is not enough either; the servo goes on
            // stamping the compressor's own gain movement back onto the output.
            //
            // The replacement is open loop: what the compression law implies,
            // plus whatever it takes to put the programme at SLAM_TARGET_DB.
            // Referenced to the compressor's own programme level, so any source
            // lands in the same place and the drive cannot drift away from the
            // threshold. The energy measurement below keeps running regardless,
            // so turning the knob back down re-engages the makeup from a live
            // value rather than from a stale one.
            // Not until the programme level has been measured: unprimed it
            // reads -60 dB, which asks for the full 36 dB of drive, so pressing
            // play used to lift the count-in by 36 dB and brickwall the first
            // word for half a second before it settled.
            if (slam01 > 0.0f && compressor.isProgrammeLevelPrimed())
            {
                const float progDB  = compressor.getProgrammeLevelDB();
                const float driveDB = juce::jlimit(0.0f, SLAM_MAX_DRIVE_DB, SLAM_TARGET_DB - progDB)
                                    * compressor.getDriveScale();
                float wallDB = compressor.getStaticMakeupDB() + driveDB;
                if (! std::isfinite(wallDB)) wallDB = 0.0f;
                makeupDB += slam01 * (wallDB - makeupDB);
                makeupDB = juce::jlimit(0.0f, SLAM_MAKEUP_MAX_DB, makeupDB);
            }
            compressor.displayMakeupDB = makeupDB;   // for the before/after timeline

            // Loudness of the compressor's output measured BEFORE makeup, so
            // TRUE LEVEL does not have to discover the makeup through an 800 ms
            // average behind a 0.5 dB / 50 ms slew. Makeup is a pure gain and
            // the processor knows it exactly, so it is added analytically below
            // and reaches the match instantly. Measuring through it was fine
            // while makeup only ever undid the reduction; against the wall's
            // drive it meant moving the knob into the top third overshot by
            // about 22 dB for a second or two before the match caught up.
            {
                float kSumSq = 0.0f;
                for (int i = 0; i < numSamples; ++i) {
                    float mono = (left[i] + right[i]) * 0.5f;
                    float kFiltered = applyBiquad(mono, kShelfOut, kShelfCoeffs);
                    kFiltered = applyBiquad(kFiltered, kHPOut, kHPCoeffs);
                    kSumSq += kFiltered * kFiltered;
                }
                const float blockMS = kSumSq / (float)numSamples;
                const float sm = std::exp(-(float)numSamples / (float)(currentSampleRate * 0.800));
                smoothedOutMS = smoothedOutMS * sm + blockMS * (1.0f - sm);
                if (! std::isfinite(smoothedOutMS) || smoothedOutMS < 0.0f) smoothedOutMS = 0.0f;
                const float smSlow = std::exp(-(float)numSamples / (float)(currentSampleRate * MAKEUP_SEC));
                slowOutMS = slowOutMS * smSlow + blockMS * (1.0f - smSlow);
                if (! std::isfinite(slowOutMS) || slowOutMS < 0.0f) slowOutMS = 0.0f;
            }

            float makeupLin = std::pow(10.0f, makeupDB / 20.0f);
            {
                float mkDelta = (makeupLin - prevMakeupLin) / (float)numSamples;
                float curMk = prevMakeupLin;
                for (int i = 0; i < numSamples; ++i) {
                    curMk += mkDelta;
                    left[i] *= curMk;
                    right[i] *= curMk;
                }
            }
            prevMakeupLin = makeupLin;

            // 5. Gain match, from the pre-makeup measurement above plus the
            // makeup applied analytically.
            {
                const float preMakeupDB = (smoothedOutMS > 1.0e-20f)
                                        ? 10.0f * std::log10(smoothedOutMS) : -100.0f;
                smoothedOutLUFS = std::sqrt(smoothedOutMS) * makeupLin;   // for the UI

                float inLevelDB = (smoothedInLUFS > 1e-10f) ? 20.0f * std::log10(smoothedInLUFS) : -100.0f;
                float outLevelDB = preMakeupDB + makeupDB;
                if (inLevelDB > -50.0f && outLevelDB > -50.0f) {
                    // Both large terms are known rather than measured. Makeup is
                    // exact, and the compressor's own contribution is very nearly
                    // the reduction it reports, so only the difference between
                    // the two — a small, slowly varying correction for the fact
                    // that one is K-weighted loudness and the other is a detector
                    // reading — is left on the slow, slew-limited path.
                    //
                    // Leaving the whole residual on that path left a 9 dB dip for
                    // about a second after a knob move into the top third: the
                    // makeup half had already been subtracted while the half that
                    // pays for it was still crawling at 0.5 dB / 50 ms.
                    // The same crossfade the makeup's base term uses, so the two
                    // cancel exactly and what is left for the match to apply is
                    // the drive alone — which moves with the knob, not behind it.
                    // Using the reported reduction here instead left a 16 dB dip
                    // for a second: at the top the makeup's base is the law's
                    // predicted reduction, which moves instantly, while the
                    // reported one is a 500 ms average that does not.
                    float baseResidualDB = predictedDB;
                    const float fastResidualDB = juce::jlimit(0.0f, SLAM_MAKEUP_MAX_DB, baseResidualDB);
                    float trimDB = (inLevelDB - preMakeupDB) - fastResidualDB;
                    if (! std::isfinite(trimDB)) trimDB = 0.0f;
                    trimDB = juce::jlimit(-12.0f, 12.0f, trimDB);
                    const float blockTimeMs = (float)numSamples / (float)currentSampleRate * 1000.0f;
                    const float maxDelta = 0.5f * blockTimeMs / 50.0f;
                    matchResidualDB = juce::jlimit(matchResidualDB - maxDelta,
                                                   matchResidualDB + maxDelta, trimDB);

                    float diffDB = juce::jlimit(-(SLAM_MAKEUP_MAX_DB), 6.0f,
                                                fastResidualDB + matchResidualDB - makeupDB);
                    gainMatchOffsetDB.store(diffDB);
                } else {
                    float prevOffset = gainMatchOffsetDB.load();
                    float fadeCoeff = std::exp(-(float)numSamples / (float)(currentSampleRate * 0.100f));
                    gainMatchOffsetDB.store(prevOffset * fadeCoeff);
                }
            }

            // 6. Apply gain match (HONEST mode) — per-sample interpolated with slew limit
            if (gainMatchEnabled.load() || honestMode.load()) {
                // Already slew-limited where it is computed, and its makeup
                // half is deliberately not — re-limiting it here would put the
                // lag straight back. Per-sample interpolation below still keeps
                // the gain change itself smooth.
                float offsetDB = gainMatchOffsetDB.load();
                float offsetLin = std::pow(10.0f, offsetDB / 20.0f);
                float offDelta = (offsetLin - prevOffsetLin) / (float)numSamples;
                float curOff = prevOffsetLin;
                for (int i = 0; i < numSamples; ++i) {
                    curOff += offDelta;
                    left[i] *= curOff;
                    right[i] *= curOff;
                }
                prevOffsetLin = offsetLin;

            } else {
                prevOffsetLin = 1.0f;
                gainMatchOffsetDB.store(0.0f);  // reset so HONEST starts clean
            }

            // 7. Limiter — last gain stage before the mix.
            // It sits after HONEST rather than before it: HONEST can boost by up
            // to 6 dB, so applying it downstream of the limiter let it push past
            // the ceiling, and the tanh waveshaper that used to patch that over
            // was the last un-oversampled nonlinearity in the chain. With the
            // limiter behind it the ceiling is binding again and the waveshaper
            // is unnecessary. The loudness measurement above still happens
            // before any gain match, so there is no feedback path.
            limiter.process(left, right, numSamples, CEILING_DB);

            // 7b. Safety clamp. The limiter holds the ceiling to within 0.03 dB
            // now, so this only has to catch that residue. It used to be a
            // rational saturator starting 2.5 dB *below* the ceiling, which made
            // it the real peak controller — and being un-oversampled it produced
            // -33 dBc of aliasing at 3 kHz, right in the sibilance band. A tight
            // clamp shapes so little that its harmonics are negligible.
            {
                const float ceiling = std::pow(10.0f, CEILING_DB / 20.0f);
                for (int i = 0; i < numSamples; ++i) {
                    left[i]  = juce::jlimit(-ceiling, ceiling, left[i]);
                    right[i] = juce::jlimit(-ceiling, ceiling, right[i]);
                }
            }

            // 9. Latency-compensated Dry/Wet Mix — per-sample interpolated.
            // Must match totalWetLatency exactly, clipper oversampler included,
            // or the two paths comb against each other.
            const int effectiveWetLatency = totalWetLatency;

            if (mixAmt < 0.999f || prevMixWet < 0.999f) {
                float mixDelta = (mixAmt - prevMixWet) / (float)numSamples;
                float curWet = prevMixWet;
                int writeBase = (dryDelayWritePos - numSamples + dlySize * 2) % dlySize;
                for (int i = 0; i < numSamples; ++i) {
                    curWet += mixDelta;
                    float wet = curWet, dry = 1.0f - curWet;
                    int readPos = (writeBase + i - effectiveWetLatency + dlySize * 2) % dlySize;
                    left[i]  = dryDelayL[(size_t)readPos] * dry + left[i] * wet;
                    right[i] = dryDelayR[(size_t)readPos] * dry + right[i] * wet;
                }
            }
            prevMixWet = mixAmt;

            // 10. Out Gain — a true output level, applied to the finished mix so
            // it cannot shift the dry/wet balance, and per-sample ramped so
            // automating it does not zipper. Placed after everything: it sets
            // level without changing how hard anything upstream works.
            {
                float outTrimLin = std::pow(10.0f, outTrimDB / 20.0f);
                float trimDelta = (outTrimLin - prevOutTrimLin) / (float)numSamples;
                float curTrim = prevOutTrimLin;
                for (int i = 0; i < numSamples; ++i) {
                    curTrim += trimDelta;
                    left[i] *= curTrim;
                    right[i] *= curTrim;
                }
                prevOutTrimLin = outTrimLin;
            }
        }
    }
    else
    {
        // Bypassed: read the raw input back out delayed by the wet latency, so a
        // bypassed instance stays aligned with the rest of the session instead of
        // arriving early. Reads the dedicated bypass line, which always holds raw
        // input — the Mix line is written after trim, HPF and De-Click, so
        // bypassing used to start with up to 12 dB of trim baked in.
        {
            const int bdSize = (int)bypassDelayL.size();
            const int base = (bypassDelayWritePos - numSamples + bdSize * 2) % bdSize;
            for (int i = 0; i < numSamples; ++i) {
                int readPos = (base + i - totalWetLatency + bdSize * 2) % bdSize;
                left[i]  = bypassDelayL[(size_t)readPos];
                right[i] = bypassDelayR[(size_t)readPos];
            }
        }
    }

    // DC Blocker — always on, catches DC from input saturation and any processing
    // 1st-order HPF at ~5Hz: y[n] = x[n] - x[n-1] + R * y[n-1]
    {
        for (int i = 0; i < numSamples; ++i) {
            float outL = left[i] - dcPrevInL + dcBlockCoeff * dcBlockL;
            float outR = right[i] - dcPrevInR + dcBlockCoeff * dcBlockR;
            dcPrevInL = left[i]; dcPrevInR = right[i];
            dcBlockL = outL; dcBlockR = outR;
            left[i] = outL; right[i] = outR;
        }
        // This filter has no path back from a non-finite state, so check once
        // per block rather than per sample.
        if (! std::isfinite(dcBlockL) || ! std::isfinite(dcBlockR)
            || ! std::isfinite(dcPrevInL) || ! std::isfinite(dcPrevInR)) {
            dcBlockL = dcBlockR = dcPrevInL = dcPrevInR = 0.0f;
        }
        // The DC blocker runs after the safety clamp, so it was the last thing
        // to touch the samples and could put them back over the ceiling. It
        // never mattered while the chain was unity gain and nothing came near
        // -0.3 dBFS; with the drive above it does. Only the processed path — a
        // hot bypassed source still passes through untouched.
        if (! bypassed) {
            const float ceiling = std::pow(10.0f, CEILING_DB / 20.0f);
            for (int i = 0; i < numSamples; ++i) {
                left[i]  = juce::jlimit(-ceiling, ceiling, left[i]);
                right[i] = juce::jlimit(-ceiling, ceiling, right[i]);
            }
        }
    }

    // Bypass crossfade: smooth transition when toggling bypass
    if (bypassed != prevBypassed) {
        for (int i = 0; i < ns; ++i) {
            float t = (float)i / (float)ns;
            // Cosine crossfade: smooth S-curve
            float fade = 0.5f * (1.0f - std::cos(t * juce::MathConstants<float>::pi));
            if (bypassed) {
                // Fading TO bypass: processed → dry
                left[i]  = left[i] * (1.0f - fade) + fadeFromL[(size_t)i] * fade;
                right[i] = right[i] * (1.0f - fade) + fadeFromR[(size_t)i] * fade;
            } else {
                // Fading FROM bypass: dry → processed
                left[i]  = fadeFromL[(size_t)i] * (1.0f - fade) + left[i] * fade;
                right[i] = fadeFromR[(size_t)i] * (1.0f - fade) + right[i] * fade;
            }
        }
        prevBypassed = bypassed;
    }

    // Output peak metering (LUFS already measured pre-match above)
    float outPL = 0, outPR = 0;
    for (int i = 0; i < numSamples; ++i) {
        outPL = std::max(outPL, std::abs(left[i]));
        outPR = std::max(outPR, std::abs(right[i]));
    }
    outputPeakL.store(outPL); outputPeakR.store(outPR);
    outputClipping.store(outPL > 0.999f || outPR > 0.999f);
    outputRMS.store(smoothedOutLUFS);

    compGainReductionDB.store(bypassed ? 0.0f : compressor.getGainReductionDB());
    limiterGainReductionDB.store(bypassed ? 0.0f : limiter.getGainReductionDB());
    gateIsOpen.store(bypassed ? true : compressor.isGateOpen());
    gateReductionDB.store(bypassed ? 0.0f : compressor.getGateReductionDB());
}

juce::AudioProcessorEditor* SmartCompProcessor::createEditor() { return new SmartCompEditor(*this); }

juce::AudioProcessorParameter* SmartCompProcessor::getBypassParameter() const
{
    return apvts.getParameter("bypass");
}

void SmartCompProcessor::getStateInformation(juce::MemoryBlock& destData)
{
    auto state = apvts.copyState();
    // AUTO and TRUE LEVEL are plain atomics rather than APVTS parameters, so
    // copyState does not carry them and neither survived a session reload —
    // AUTO being the plugin's headline feature, silently off every time the
    // project was reopened. Saved beside the parameters rather than turned into
    // parameters, which would also expose them to host automation: that is a
    // feature decision, this is a bug.
    state.setProperty("rideMode", rideMode.load(), nullptr);
    state.setProperty("honestMode", honestMode.load(), nullptr);
    std::unique_ptr<juce::XmlElement> xml(state.createXml());
    copyXmlToBinary(*xml, destData);
}

void SmartCompProcessor::setStateInformation(const void* data, int sizeInBytes)
{
    std::unique_ptr<juce::XmlElement> xml(getXmlFromBinary(data, sizeInBytes));
    if (xml != nullptr && xml->hasTagName(apvts.state.getType()))
    {
        auto tree = juce::ValueTree::fromXml(*xml);
        apvts.replaceState(tree);
        // Absent in states written before this was saved, so both default to
        // off exactly as they did then.
        rideMode.store((bool) tree.getProperty("rideMode", false));
        honestMode.store((bool) tree.getProperty("honestMode", false));
    }
}

juce::AudioProcessor* JUCE_CALLTYPE createPluginFilter() { return new SmartCompProcessor(); }

// ===== K-Weighting Filters for LUFS (ITU-R BS.1770) =====
void SmartCompProcessor::computeKWeightingCoeffs(double sampleRate)
{
    // Stage 1: Pre-filter (high shelf, ~+4dB above 1681Hz)
    // Derived from ITU-R BS.1770-4 specification
    {
        double Vh = std::pow(10.0, 3.999843853973347 / 20.0);
        double Vb = std::pow(Vh, 0.4996667741545416);
        double fc = 1681.974450955533;
        double Q  = 0.7071752369554196;
        double K  = std::tan(juce::MathConstants<double>::pi * fc / sampleRate);
        double K2 = K * K;
        // The denominator is 1 + K/Q + K^2 — no Vb. It used to carry a stray Vb
        // in both a0 and a2, which raised the shelf's effective Q from 0.707 to
        // 0.890 and made it resonant: +4.44 dB at 1682 Hz against a +4.00 dB
        // asymptote, a 2 dB error, peaking near +4.95 dB around 1.2 kHz.
        // Without it these match BS.1770-4 Table 1 to 14 digits.
        double a0 = 1.0 + K / Q + K2;
        kShelfCoeffs.b0 = (float)((Vh + Vb * K / Q + K2) / a0);
        kShelfCoeffs.b1 = (float)((2.0 * (K2 - Vh)) / a0);
        kShelfCoeffs.b2 = (float)((Vh - Vb * K / Q + K2) / a0);
        kShelfCoeffs.a1 = (float)((2.0 * (K2 - 1.0)) / a0);
        kShelfCoeffs.a2 = (float)((1.0 - K / Q + K2) / a0);
    }

    // Stage 2: RLB weighting (high-pass, ~38Hz)
    {
        double fc = 38.13547087602444;
        double Q  = 0.5003270373238773;
        double K  = std::tan(juce::MathConstants<double>::pi * fc / sampleRate);
        double K2 = K * K;
        double a0 = 1.0 + K / Q + K2;
        // BS.1770 specifies b = {1, -2, 1} un-normalised, so the passband gain is
        // exactly 1. Dividing these by a0 made the reading sample-rate dependent
        // by about 0.04 dB.
        kHPCoeffs.b0 = 1.0f;
        kHPCoeffs.b1 = -2.0f;
        kHPCoeffs.b2 = 1.0f;
        kHPCoeffs.a1 = (float)((2.0 * (K2 - 1.0)) / a0);
        kHPCoeffs.a2 = (float)((1.0 - K / Q + K2) / a0);
    }
}

float SmartCompProcessor::applyBiquad(float x, BiquadState& s, const BiquadCoeffs& c)
{
    float y = c.b0 * x + c.b1 * s.x1 + c.b2 * s.x2 - c.a1 * s.y1 - c.a2 * s.y2;
    s.x2 = s.x1; s.x1 = x;
    s.y2 = s.y1; s.y1 = y;
    return y;
}
