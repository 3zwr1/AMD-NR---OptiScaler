// Copyright (c) 2026 3zwr1 (AMDNR). Part of AMDNR (GPL-3.0; see Licenses/AMDNR_NOTICE.txt).
// SPDX-License-Identifier: GPL-3.0-or-later
#pragma once
#include <d3d12.h>
#include <d3dcompiler.h>
#include "SystemCompiler.h"
#include <wrl/client.h>
#include <stdexcept>
#include <string>
#include <cstring>
#include <algorithm>
namespace AmdPreSr {
// Optional temporal stabilisation of the final NR colour, run on the render
// queue AFTER the model/look/rtgi and BEFORE Super Resolution. It blends the
// current frame with the previous frame's stabilised result, reprojected by the
// same motion vectors (and pixel scale) the model was handed, and clamps that
// history to the current 3x3 neighbourhood so a wrong-sign or disoccluded vector
// degrades to a bounded local artefact instead of a smear. At strength 0 (or on
// a reset) the current frame is written through unchanged, so the pass is
// byte-identical when off. This does NOT touch the HIP runtime or any per-slot
// buffer: like lookColour/scaleOutput it is a shared, render-queue-ordered pass.
//
// It also keeps its own one-frame depth history (ping-ponged alongside the
// colour) purely to reject disocclusions: the colour clamp alone can be fooled
// when a reprojected sample happens to land on similarly-coloured but different
// geometry (the classic ghost trail behind a moving object). A large relative
// depth change at the same reprojected position means "different surface", so
// history is dropped outright there regardless of colour. See design/
// temporal-stability.md's "Follow-ups" for why this was deferred originally.
//
// Model interleave takes a separate, self-contained path in the shader below; see
// the long note at the MODEL INTERLEAVE marker for what it does and why. The
// non-interleave paths here are the original ones and are untouched by it.
inline constexpr char TemporalStabilityShader[] = R"(
Texture2D<float4> cur  : register(t0);
Texture2D<float4> hist : register(t1);
Texture2D<float4> mv   : register(t2);
Texture2D<float> depthCur  : register(t3);
Texture2D<float> depthHist : register(t4);
// Last frame's motion vectors, already in PIXELS. Kept for exactly one reason, set out in
// full at the divergence block below: it is the only signal available to this pass that
// can see a screen-space effect being dragged along by the background it happens to lie on.
Texture2D<float2> mvHist : register(t5);
// The frame as the model RECEIVED it, and the previous frame's residual. Both exist only
// for the Residual temporal preset; the host binds the colour texture and the colour
// history in their place when it is off, so the registers are always valid and no other
// path ever reads them.
Texture2D<float4> base : register(t6);
Texture2D<float4> residHist : register(t7);
// THE GAME'S OWN REACTIVE MASK, and the input this pass should have had from the start.
//
// Every guard in this file tries to DETECT content whose motion vectors do not describe
// it - by depth, by vector divergence, by colour. The engine already knows. A reactive
// mask is exactly the channel where a game marks the pixels whose colour this frame
// cannot be predicted from the last one: particles, smoke, transparencies, animated
// alpha, anything composited after the velocity pass. FSR and DLSS both take one for this
// precise purpose, OptiScaler already fills the NGX slot from the title's own dispatch,
// and this pass simply never read it.
//
// That is why every fix so far has been a repair rather than a cure. The smoke in Forza,
// the car's contact shadow in GTA, the rim on the character in Silent Hill - all of them
// are pixels the engine had already flagged, and we were re-deriving the flag badly from
// geometry that was, by construction, telling us nothing was wrong.
//
// Bound to a 1x1 zero texture when the title publishes none, so the sample is always
// valid and reads as "not reactive" everywhere.
Texture2D<float4> reactive : register(t8);
// The model's tonal transfer, 64 ratios (raw luminance bin -> model/raw), measured on the
// last model frame by the ToneAccumulate/ToneLut passes below. Read by v2's fallbacks.
// Floats [64..127] are Edit accumulation's HDR-safe copy of the same transfer (half-stop
// bins of log2 raw luminance, glided every frame) and [128..191] its raw per-bin target;
// [192..255] / [256..319] the model's detail ratio in the same bins (danielblnc).
ByteAddressBuffer lut : register(t9);
// EDIT ACCUMULATION ONLY (presets 10/11): the previous frame's RAW pixel in rgb, linear, and
// in alpha the relative temporal noise learned for that pixel. It is what lets the carried
// edit be validated raw against raw, at exactly corresponding points, on BOTH frame types -
// the test Guided fill v2 could only run on filled frames and only against a reprojected
// model picture minus an edit (misregistered by construction). Other presets never read it.
Texture2D<float4> rawHist : register(t10);
RWTexture2D<float4> dst : register(u0);
RWTexture2D<float> depthDst : register(u1);
RWTexture2D<float2> mvDst : register(u2);
// The residual history is ping-ponged separately from the colour. Writing it into `dst`
// would have been cheaper by two textures and wrong: `dst` is both this pass's OUTPUT and
// next frame's colour history, so a residual stored there would be handed to Super
// Resolution as if it were a picture.
RWTexture2D<float4> residDst : register(u3);
// Adaptive interleave counters, at a quarter of the pixels: dword 0 = pixels of this filled
// frame that fell back, dword 1 = pixels in motion by more than a pixel. The host zeroes
// them before the dispatch and reads them a few frames later.
RWByteAddressBuffer changeCount : register(u6);
// (Edit accumulation adds dwords 10/11 - model detail the fit missed / model detail in total,
// on model frames - and dword 12 - pixels refused by the raw-against-raw test alone. The view
// covers all 16 dwords of the buffer; it covered 4 until this build, so every write from
// dword 4 on - the Model-frame ghost meter, the Self-tuning totals - was silently dropped.)
// Self-tuning interleave (preset 8): per-tile candidate error sums (4 dwords per 16x16 tile:
// A, B, C, count) and the smoothed per-tile scores the skipped frames blend by.
RWByteAddressBuffer tileAcc : register(u7);
RWTexture2D<float4> tileScore : register(u8);
// The same, per PIXEL CLASS instead of per position: 64 bins of (motion divergence x
// motion length x depth-mismatch verdict x same-surface verdict). A tile says where a
// candidate fails; a class says on WHAT KIND of pixel it fails, learned from every such
// pixel in the frame at once - which is how a moving arm inside a mostly-static tile is
// told apart from the tile it sits in.
RWByteAddressBuffer featAcc : register(u9);
RWTexture2D<float4> featScore : register(u10);
// This frame's raw + learned noise, for the next frame's rawHist (Edit accumulation only).
RWTexture2D<float4> rawDst : register(u11);
SamplerState samp : register(s0);
// `interleaved` is 1 on BOTH frame types while model interleave is running, 0
// otherwise (it replaces a padding word, so the constant count is unchanged). It
// exists because model frames and fill frames must share their statistics: any
// asymmetry between the two paths lands on screen at the interleave cadence, which
// is the whole family of bugs this file has been chasing. At 0 every non-interleave
// path below is bit-for-bit what it was.
cbuffer P : register(b0) { uint w; uint h; float alpha; uint reset; float mvScaleX; float mvScaleY; float ghostReject; uint mode; float threshold; float interleaved; float detailScale; float modelFrame; float sharpFill; float debugView; float extraTemporal; float residualTemporal; float residualCap; float depthInv; float heldGhostBound; float reactiveAvail; float lutAvail; float jitterDx; float jitterDy; float sharpGain; float staticRelax; float staticDebug; }
// How reactive this pixel is, 0..1, or 0 everywhere when the title publishes no mask.
// Sampled by UV rather than by texel so a mask at a different resolution than the render
// target still lands on the right pixel.
float reactiveAt(int2 p)
{
 if (reactiveAvail < 0.5) return 0.0;
 float2 uv = (float2(p) + 0.5) / float2(float(w), float(h));
 float4 r = reactive.SampleLevel(samp, uv, 0);
 // Titles disagree about which channel carries it: FSR's generated mask uses red, a few
 // fill all four. The largest of the channels the FORMAT HAS is taken (reactiveAvail is
 // the channel count, 1..3): a one-channel mask (R8/R16/R32) reads back alpha = 1.0 for the
 // missing component, and max over all four then said "everything is reactive" - keep 0
 // over the whole frame, and in the lmxxf carry that meant no edit ever landed (GTA V
 // Enhanced publishes such a mask; the titles tested before publish none). Alpha is
 // never read: an RGBA mask with the value in red carries opaque 1.0 there too.
 float v = reactiveAvail < 1.5 ? r.x : reactiveAvail < 2.5 ? max(r.x, r.y) : max(max(r.x, r.y), r.z);
 return isfinite(v) ? saturate(v) : 0.0;
}
// STILL-SURFACE STEADINESS (#5, 0.3.3.2 rebuild; staticRelax, 0 = off and never read). A shadow or a flat area that
// pulses on geometry that is not moving collapses the clip box (sigma ~ 0 on a flat surface, so the clamp is the
// identity and the ghost term saturates), and lmxxf's agreement clamp shrinks to the fresh edit's own size on dark
// pixels. Both are widened, only where the pixel provably has not moved, by a floor proportional to its brightness.
// stillWeight: 1 on a pixel that provably has not moved (own, nearest-depth and last frame's vector at its source all
// under 1/4 px, fading out by 1 px; depth well inside the disocclusion tolerance; not reactive), 0 otherwise. Ramps,
// never a switch.
float stillWeight(int2 p, float2 mDil, float2 fromPx, float dNow, float dThen, float depthTol) {
 float2 mOwn = mv.Load(int3(p,0)).xy * float2(mvScaleX, mvScaleY);
 float2 uvF = clamp(fromPx, float2(0.5,0.5), float2(float(w), float(h)) - 0.5) / float2(float(w), float(h));
 float2 mThen = mvHist.SampleLevel(samp, uvF, 0);
 if (!all(isfinite(mOwn)) || !all(isfinite(mDil)) || !all(isfinite(mThen)) || !isfinite(dNow) || !isfinite(dThen)) return 0.0;
 float mMax = max(max(length(mOwn), length(mDil)), length(mThen));
 float wM = 1.0 - smoothstep(0.25, 1.0, mMax);
 float wD = 1.0 - smoothstep(0.25, 0.5, abs(dNow - dThen) / max(depthTol, 1e-6));
 return wM * wD * (1.0 - reactiveAt(p));
}
// Luminance-aware floor in tm units: a relative change r in linear light is r*t*(1-t) in tm (d tm/dx = (1-t)^2).
// 25% x s, vanishing on highlights; the 1e-4 linear term only keeps black from zero width.
float3 stillFloorTm(float3 t, float s) { t = saturate(t); return s * (1.0 - t) * (0.25 * t + 1e-4 * (1.0 - t)); }
// The same floor for the edit clamps (linear units, max channel). Full widening while the disagreement is within
// lim+floor, none past lim+3*floor: a big disagreement is a real change and keeps the old bound.
float stillLimit(float lim, float dm, float3 b, float s) {
 float fS = s * (0.25 * max(max(b.x, max(b.y, b.z)), 0.0) + 1e-4);
 if (!(fS > 0.0) || !isfinite(dm)) return lim;
 return lim + fS * (1.0 - saturate((dm - lim - fS) / (2.0 * fS)));
}
// 5-tap Catmull-Rom bicubic history sample (Karis/Jimenez optimisation): sharper
// than bilinear so reprojected history keeps detail instead of blurring a little
// more each frame - fewer accumulated ghosts, clearer interleave fill.
float3 sampleHistory(float2 posPx) {
 float2 res = float2(float(w), float(h));
 float2 texPos1 = floor(posPx - 0.5) + 0.5;
 float2 f = posPx - texPos1;
 float2 c0 = f * (-0.5 + f * (1.0 - 0.5*f));
 float2 c1 = 1.0 + f*f * (-2.5 + 1.5*f);
 float2 c2 = f * (0.5 + f * (2.0 - 1.5*f));
 float2 c3 = f*f * (-0.5 + 0.5*f);
 float2 c12 = c1 + c2;
 float2 off12 = c2 / max(c12, 1e-5);
 float2 p0 = (texPos1 - 1.0) / res;
 float2 p3 = (texPos1 + 2.0) / res;
 float2 p12 = (texPos1 + off12) / res;
 float3 r = 0.0;
 r += hist.SampleLevel(samp, float2(p12.x, p0.y ), 0).rgb * (c12.x * c0.y);
 r += hist.SampleLevel(samp, float2(p0.x,  p12.y), 0).rgb * (c0.x  * c12.y);
 r += hist.SampleLevel(samp, float2(p12.x, p12.y), 0).rgb * (c12.x * c12.y);
 r += hist.SampleLevel(samp, float2(p3.x,  p12.y), 0).rgb * (c3.x  * c12.y);
 r += hist.SampleLevel(samp, float2(p12.x, p3.y ), 0).rgb * (c12.x * c3.y);
 float wsum = (c12.x*c0.y)+(c0.x*c12.y)+(c12.x*c12.y)+(c3.x*c12.y)+(c12.x*c3.y);
 float3 cr = max(r / max(wsum, 1e-5), 0.0);
 // Clamp the bicubic result to the four nearest texels. Catmull-Rom has negative
 // lobes that overshoot at edges and turn a small reprojection error into a crisp
 // doubled (ghost) edge; clamping keeps the sub-pixel sharpness without the ring.
 int2 mxi = int2(int(w)-1, int(h)-1);
 int2 lo = clamp(int2(floor(posPx-0.5)), int2(0,0), mxi);
 int2 hi = min(lo+1, mxi);
 float3 a00 = hist.Load(int3(lo,0)).rgb;
 float3 a10 = hist.Load(int3(int2(hi.x,lo.y),0)).rgb;
 float3 a01 = hist.Load(int3(int2(lo.x,hi.y),0)).rgb;
 float3 a11 = hist.Load(int3(hi,0)).rgb;
 float3 tmn = min(min(a00,a10),min(a01,a11));
 float3 tmx = max(max(a00,a10),max(a01,a11));
 return clamp(cr, tmn, tmx);
}
// The same clamped Catmull-Rom, for the carried EDIT (residHist). Signed data, so the
// non-negative clamp of sampleHistory is left out; the clamp to the four nearest texels
// stays, for the same reason. Bilinear was used here first and it is why Guided fill's
// filled frames came out softer than its model frames under motion: the edit holds the
// model's high-frequency detail, and a bilinear resample at a fractional offset is a
// low-pass on exactly that band.
float3 sampleResid(float2 posPx) {
 float2 res = float2(float(w), float(h));
 float2 texPos1 = floor(posPx - 0.5) + 0.5;
 float2 f = posPx - texPos1;
 float2 c0 = f * (-0.5 + f * (1.0 - 0.5*f));
 float2 c1 = 1.0 + f*f * (-2.5 + 1.5*f);
 float2 c2 = f * (0.5 + f * (2.0 - 1.5*f));
 float2 c3 = f*f * (-0.5 + 0.5*f);
 float2 c12 = c1 + c2;
 float2 off12 = c2 / max(c12, 1e-5);
 float2 p0 = (texPos1 - 1.0) / res;
 float2 p3 = (texPos1 + 2.0) / res;
 float2 p12 = (texPos1 + off12) / res;
 float3 r = 0.0;
 r += residHist.SampleLevel(samp, float2(p12.x, p0.y ), 0).rgb * (c12.x * c0.y);
 r += residHist.SampleLevel(samp, float2(p0.x,  p12.y), 0).rgb * (c0.x  * c12.y);
 r += residHist.SampleLevel(samp, float2(p12.x, p12.y), 0).rgb * (c12.x * c12.y);
 r += residHist.SampleLevel(samp, float2(p3.x,  p12.y), 0).rgb * (c3.x  * c12.y);
 r += residHist.SampleLevel(samp, float2(p12.x, p3.y ), 0).rgb * (c12.x * c3.y);
 float wsum = (c12.x*c0.y)+(c0.x*c12.y)+(c12.x*c12.y)+(c3.x*c12.y)+(c12.x*c3.y);
 float3 cr = r / max(wsum, 1e-5);
 int2 mxi = int2(int(w)-1, int(h)-1);
 int2 lo = clamp(int2(floor(posPx-0.5)), int2(0,0), mxi);
 int2 hi = min(lo+1, mxi);
 float3 a00 = residHist.Load(int3(lo,0)).rgb;
 float3 a10 = residHist.Load(int3(int2(hi.x,lo.y),0)).rgb;
 float3 a01 = residHist.Load(int3(int2(lo.x,hi.y),0)).rgb;
 float3 a11 = residHist.Load(int3(hi,0)).rgb;
 float3 tmn = min(min(a00,a10),min(a01,a11));
 float3 tmx = max(max(a00,a10),max(a01,a11));
 return clamp(cr, tmn, tmx);
}
// The same again for t6 (`base`), which the lmxxf carry (preset 9) binds to the model's FRESH
// edit: signed data in the previous frame's pixel space, reprojected like residHist is.
float3 sampleBaseCR(float2 posPx) {
 float2 res = float2(float(w), float(h));
 float2 texPos1 = floor(posPx - 0.5) + 0.5;
 float2 f = posPx - texPos1;
 float2 c0 = f * (-0.5 + f * (1.0 - 0.5*f));
 float2 c1 = 1.0 + f*f * (-2.5 + 1.5*f);
 float2 c2 = f * (0.5 + f * (2.0 - 1.5*f));
 float2 c3 = f*f * (-0.5 + 0.5*f);
 float2 c12 = c1 + c2;
 float2 off12 = c2 / max(c12, 1e-5);
 float2 p0 = (texPos1 - 1.0) / res;
 float2 p3 = (texPos1 + 2.0) / res;
 float2 p12 = (texPos1 + off12) / res;
 float3 r = 0.0;
 r += base.SampleLevel(samp, float2(p12.x, p0.y ), 0).rgb * (c12.x * c0.y);
 r += base.SampleLevel(samp, float2(p0.x,  p12.y), 0).rgb * (c0.x  * c12.y);
 r += base.SampleLevel(samp, float2(p12.x, p12.y), 0).rgb * (c12.x * c12.y);
 r += base.SampleLevel(samp, float2(p3.x,  p12.y), 0).rgb * (c3.x  * c12.y);
 r += base.SampleLevel(samp, float2(p12.x, p3.y ), 0).rgb * (c12.x * c3.y);
 float wsum = (c12.x*c0.y)+(c0.x*c12.y)+(c12.x*c12.y)+(c3.x*c12.y)+(c12.x*c3.y);
 float3 cr = r / max(wsum, 1e-5);
 int2 mxi = int2(int(w)-1, int(h)-1);
 int2 lo = clamp(int2(floor(posPx-0.5)), int2(0,0), mxi);
 int2 hi = min(lo+1, mxi);
 float3 a00 = base.Load(int3(lo,0)).rgb;
 float3 a10 = base.Load(int3(int2(hi.x,lo.y),0)).rgb;
 float3 a01 = base.Load(int3(int2(lo.x,hi.y),0)).rgb;
 float3 a11 = base.Load(int3(hi,0)).rgb;
 float3 tmn = min(min(a00,a10),min(a01,a11));
 float3 tmx = max(max(a00,a10),max(a01,a11));
 return clamp(cr, tmn, tmx);
}
// ---- Edit accumulation helpers (presets 10/11). New names on purpose: main() already owns
// `g`, `lo`, `hi`, `m`, `mean` and `sigma`, and a helper shadowing one of them is how a
// one-letter typo becomes a silent wrong answer.
float amax3(float3 v) { return max(v.x, max(v.y, v.z)); }
// YCoCg: luma plus two chroma differences, so the raw-against-raw test weighs a change of
// colour and a change of brightness on one scale and divides both by one luma.
float3 toYCoCg(float3 c) { return float3(0.25*c.r + 0.5*c.g + 0.25*c.b, 0.5*(c.r - c.b), 0.5*c.g - 0.25*(c.r + c.b)); }
// sampleResid on all four channels: the carried danielblnc state is (gain - 1, slope - 1), and
// the slope lives in alpha. Same clamped Catmull-Rom, same clamp to the four nearest texels, per
// channel including alpha, for the same reason - no doubled edge out of the negative lobes.
float4 sampleResid4(float2 posPx) {
 float2 res = float2(float(w), float(h));
 float2 texPos1 = floor(posPx - 0.5) + 0.5;
 float2 f = posPx - texPos1;
 float2 c0 = f * (-0.5 + f * (1.0 - 0.5*f));
 float2 c1 = 1.0 + f*f * (-2.5 + 1.5*f);
 float2 c2 = f * (0.5 + f * (2.0 - 1.5*f));
 float2 c3 = f*f * (-0.5 + 0.5*f);
 float2 c12 = c1 + c2;
 float2 off12 = c2 / max(c12, 1e-5);
 float2 p0 = (texPos1 - 1.0) / res;
 float2 p3 = (texPos1 + 2.0) / res;
 float2 p12 = (texPos1 + off12) / res;
 float4 r = 0.0;
 r += residHist.SampleLevel(samp, float2(p12.x, p0.y ), 0) * (c12.x * c0.y);
 r += residHist.SampleLevel(samp, float2(p0.x,  p12.y), 0) * (c0.x  * c12.y);
 r += residHist.SampleLevel(samp, float2(p12.x, p12.y), 0) * (c12.x * c12.y);
 r += residHist.SampleLevel(samp, float2(p3.x,  p12.y), 0) * (c3.x  * c12.y);
 r += residHist.SampleLevel(samp, float2(p12.x, p3.y ), 0) * (c12.x * c3.y);
 float wsum = (c12.x*c0.y)+(c0.x*c12.y)+(c12.x*c12.y)+(c3.x*c12.y)+(c12.x*c3.y);
 float4 cr = r / max(wsum, 1e-5);
 int2 mxi = int2(int(w)-1, int(h)-1);
 int2 lo = clamp(int2(floor(posPx-0.5)), int2(0,0), mxi);
 int2 hi = min(lo+1, mxi);
 float4 a00 = residHist.Load(int3(lo,0));
 float4 a10 = residHist.Load(int3(int2(hi.x,lo.y),0));
 float4 a01 = residHist.Load(int3(int2(lo.x,hi.y),0));
 float4 a11 = residHist.Load(int3(hi,0));
 float4 tmn = min(min(a00,a10),min(a01,a11));
 float4 tmx = max(max(a00,a10),max(a01,a11));
 return clamp(cr, tmn, tmx);
}
// The model's gain for a raw luminance, from the log-domain transfer (floats [64..127] of the
// LUT: 64 bins at half a stop, log2 L in [-14, +18], glided every frame). Linear in the bin
// index, so a scene at 1500 is as well resolved as one at 0.15 - the tonemapped curve above
// puts everything past ~100 into its last bin and divides by the bin centre, which biased it.
float lutGainLog(float L) {
 if (lutAvail < 0.5) return 1.0;
 const float fb = clamp((log2(max(L, 6.1035e-5)) + 14.0) * 2.0, 0.0, 63.0);
 const int b0 = int(fb); const int b1 = min(b0 + 1, 63);
 const float gg = lerp(asfloat(lut.Load(uint((64 + b0) * 4))), asfloat(lut.Load(uint((64 + b1) * 4))), fb - float(b0));
 return (isfinite(gg) && gg > 0.0) ? clamp(gg, 1.0/16.0, 16.0) : 1.0;
}
// The model's detail ratio at a raw luminance (danielblnc; floats [192..255], the same bins and the
// same glide): how much of the raw's own local detail the model leaves, measured on answer frames.
float lutDetailLog(float L) {
 if (lutAvail < 0.5) return 1.0;
 const float fb = clamp((log2(max(L, 6.1035e-5)) + 14.0) * 2.0, 0.0, 63.0);
 const int b0 = int(fb); const int b1 = min(b0 + 1, 63);
 const float dd = lerp(asfloat(lut.Load(uint((192 + b0) * 4))), asfloat(lut.Load(uint((192 + b1) * 4))), fb - float(b0));
 return (isfinite(dd) && dd > 0.0) ? clamp(dd, 0.25, 4.0) : 1.0;
}
// The picture a carried state stands for, on THIS frame's raw.
//  danielblnc: S = (G - 1, A - 1). G is a per-channel gain of the local raw mean, offset by eps
//  so it is exact at the fit and means the same thing at any scene brightness; A is a luminance
//  slope applied to this frame's OWN detail (R - mean). So the carried thing is a local linear
//  model of what the network did (guided-filter idea, He/Sun/Tang 2010), never a picture: the
//  high band on screen is always this frame's.
//  lmxxf: S.rgb is the linear edit, as preset 9 carries it.
float3 accumOut(float4 S, bool dan, float3 R, float3 mR, float eps) {
 return dan ? (S.rgb + 1.0) * (mR + eps) - eps + (S.a + 1.0) * (R - mR) : R + S.rgb;
}
// Tonemap / inverse-tonemap. Statistics and clamps run in tm space so bright HDR
// values are not treated as outliers (see the variance-clip note in main).
float3 tmap(float3 x) { return x / (1.0 + max(x, 0.0)); }
// Bound a residual against the picture it is about to be added to.
//
// This was missing, and its absence is what striped the road with colour. `base + residual`
// is a SUM OF TWO SEPARATELY PRODUCED THINGS, and nothing about that sum is constrained to
// be a colour the scene contains - a note written in this very file days earlier, about a
// band-splitting experiment that was removed for exactly this reason, and then walked into
// again from the other direction.
//
// Scaled as one triple, never per channel: clamping channels independently lets whichever
// one hits its limit first decide the hue of the rest, which turns an over-large edit into a
// wrong-COLOURED edit. That is the iridescent fringing, not a separate bug.
//
// The floor keeps the bound from collapsing to nothing on near-black pixels, where a
// relative limit would otherwise forbid any edit at all and leave the model unable to touch
// the darkest parts of a night scene.
float3 boundResidual(float3 r, float3 b, float cap)
{
 if (cap <= 0.0) return r;
 float bound = cap * max(max(max(abs(b.r), abs(b.g)), abs(b.b)), 0.02);
 float mag = max(max(abs(r.r), abs(r.g)), abs(r.b));
 return (mag > bound) ? r * (bound / mag) : r;
}
// The largest fraction of a residual that leaves every channel of `base + residual`
// non-negative, applied to the WHOLE triple at once.
//
// This is what the cyan arcs under the car were. The residual can be negative - the model
// darkens as well as brightens - and a negative RED residual landing on grey asphalt drives
// the red channel below zero. The line that handled it was `max(base + resid, 0.0)`, which
// is a PER-CHANNEL clamp: red is pinned at zero while green and blue keep their negative
// shift, and asphalt-minus-red is cyan. The complement of the taillight that produced it,
// which is the tell.
//
// Two lines above that clamp is a comment of mine reading "scaled as one triple, never per
// channel". I wrote the rule and then broke it in the same block, because a floor does not
// look like a clamp until it rotates a hue.
//
// This is hhkbble's cube scaling from the multi-pass work on this fork, reduced to the one
// bound HDR has: there is no ceiling to hit, only zero. A residual already representable is
// returned untouched.
float3 fitResidual(float3 b, float3 r)
{
 float a = 1.0;
 [unroll] for (int i = 0; i < 3; ++i)
  if (r[i] < -1e-6) a = min(a, -b[i] / r[i]);
 return r * saturate(a);
}
// The epsilon is a divide-by-zero guard, but it also HARD-CAPS the result: tm(x)=x/(1+x)
// gives 1-y = 1/(1+x), so max(1-y, 1e-4) clips anything above x ~= 1e4. That was
// invisible while this was assumed to be roughly 0..10 content - but a real capture of
// Forza Horizon 6 has a scene mean of ~1500 and peaks of 11136, so the brightest
// highlights in the game were being clipped by ~10% on every path that round-trips
// through the tonemap. Mode 0 mixes in `c.rgb` RAW, without the round trip, so the two
// were clipped differently - one more difference between the model and fill paths, on
// the brightest pixels in the frame. 1e-6 keeps the guard and moves the cap to ~1e6,
// far above anything a colour buffer holds, and is still comfortably inside fp32.
float3 itmap(float3 y) { return y / max(1.0 - y, 1e-6); }
// 3x3 box blur of the CURRENT buffer, in tm space - the low-frequency band.
// Was 5x5. A 5x5 puts far more of the picture into the "low frequency" half, and
// whatever mode 5 below takes from the history is exactly that half - so a wide
// kernel both softens the result and hands more of the frame to the part that can
// ghost. 3x3 splits higher, keeps the image sharper, and leaves less for a stale
// history to smear.
float3 softCurTm(int2 p, int2 mx) {
 float3 s = 0.0;
 [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++)
  s += cur.Load(int3(clamp(p+int2(i,j), int2(0,0), mx),0)).rgb;
 s *= (1.0/9.0);
 return tmap(s);
}
// The SAME 5x5 box, applied to the history at its reprojected position. mode 3's
// gate asks "did the scene change here?", and it can only answer that by comparing
// like with like: the current side is necessarily low-passed (it is un-denoised, so
// it must be blurred before it means anything), and comparing a low-passed signal
// against a full-band one reports a disagreement at EVERY high-frequency feature
// whether or not anything changed. An isolated bright pixel is the worst case - the
// 5x5 divides it by 25 while the history keeps it - so the gate always read "ghost"
// on exactly the lights the user sees flickering, and dropped them to the blurred
// value. Blurring both sides with one kernel makes the gate measure change instead
// of measuring sharpness.
float3 softHistTm(float2 posPx, int2 mx) {
 int2 q = clamp(int2(floor(posPx)), int2(0,0), mx);
 float3 s = 0.0;
 [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++)
  s += hist.Load(int3(clamp(q+int2(i,j), int2(0,0), mx),0)).rgb;
 s *= (1.0/9.0);
 return tmap(s);
}
float3 histMean3(float2 posPx, int2 mx) {
 int2 q = clamp(int2(floor(posPx)), int2(0,0), mx);
 float3 s = 0.0;
 [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++)
  s += hist.Load(int3(clamp(q+int2(i,j), int2(0,0), mx),0)).rgb;
 return s * (1.0/9.0);
}
// 3x3 sigma of the DENOISED history in tonemapped units: real detail, not grain.
float histSigmaTm(float2 posPx, int2 mx) {
 int2 q = clamp(int2(floor(posPx)), int2(0,0), mx);
 float3 m1 = 0.0; float3 m2 = 0.0;
 [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++) {
  float3 v = tmap(hist.Load(int3(clamp(q+int2(i,j), int2(0,0), mx),0)).rgb);
  m1 += v; m2 += v*v;
 }
 m1 *= (1.0/9.0); m2 *= (1.0/9.0);
 float3 sg = sqrt(max(m2 - m1*m1, 0.0));
 return max(sg.x, max(sg.y, sg.z));
}
// A fallback pixel wearing the model's tone. The LUT holds, per raw-luminance bin, how
// much brighter or darker the model made pixels of that luminance on the last model
// frame; it is a property of the scene and the model, not of a position, so it needs no
// reprojection and cannot be a ghost. It fades to nothing in the near-black bins, where a
// ratio of two tiny numbers means nothing.
float3 toneFallback(float3 lin) {
 if (lutAvail < 0.5) return lin;
 float3 t = tmap(max(lin, 0.0));
 float L = saturate(dot(t, float3(0.2126, 0.7152, 0.0722)));
 float fb = L * 63.0;
 int b0 = int(fb); int b1 = min(b0 + 1, 63); float f = fb - float(b0);
 float r0 = asfloat(lut.Load(b0 * 4)); float r1 = asfloat(lut.Load(b1 * 4));
 float r = lerp(r0, r1, f);
 if (!isfinite(r)) return lin;
 r = lerp(1.0, r, saturate(L * 16.0));
 return itmap(min(t * r, 0.995));
}
// 3x3 statistics of the pre-model raw (t6), in tonemapped units: what main() computes for
// `cur`, for the frames on which `cur` is the model's output instead of the raw.
void stats3Base(int2 p, int2 mx, out float3 mean, out float3 sigma, out float3 nmin, out float3 nmax) {
 float3 m1 = 0.0; float3 m2 = 0.0; nmin = 1e30; nmax = -1e30;
 [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++) {
  float3 n = tmap(base.Load(int3(clamp(p+int2(i,j), int2(0,0), mx),0)).rgb);
  m1 += n; m2 += n*n; nmin = min(nmin,n); nmax = max(nmax,n);
 }
 mean = m1 * (1.0/9.0);
 sigma = sqrt(max(m2 * (1.0/9.0) - mean*mean, 0.0));
}
// EDIT ACCUMULATION HAS ITS OWN PIPELINE. The host compiles this source twice: once as it always
// was (without the EDIT ACCUMULATION block), and once with EDIT_ACCUM=1, which keeps only what
// presets 10/11 read - the prologue's geometry (depth dilation, motion, divergence) and that
// block - and leaves out the tonemapped 3x3 statistics every other preset builds first, the
// Residual temporal path and everything after the block. In one pipeline the block ran with the
// other presets' 75 temporaries live around it (24 on its own). Measured on the RX 9070 XT at
// 2560x1440 (GPU timestamps, synthetic frames): danielblnc model/filled frame 0.77/0.58 ms ->
// 0.56/0.41 ms (Guided fill v2: 0.59/0.59), lmxxf fresh/carry 0.75/0.62 -> 0.56/0.44 (Classic
// carry: 0.55/0.49). (Summing the counters in groupshared memory first was tried as well: with
// the barriers it needs it measured 0.003 ms slower, so the atomics stay per pixel.)
#ifndef EDIT_ACCUM
#define EDIT_ACCUM 0
#endif
[numthreads(8,8,1)] void main(uint3 tid:SV_DispatchThreadID) {
 if (tid.x>=w || tid.y>=h) return;
 int2 p = int2(tid.xy);
 // Jitter compensation (see the host): where this pixel's content was on the previous
 // frame's grid is the motion PLUS the change of the grid itself.
 const float2 jit = float2(jitterDx, jitterDy);
 float4 c = cur.Load(int3(p,0));
 // Depth history is written unconditionally, before any branch, so it stays valid
 // every dispatch regardless of which path returns - the guarantee `dst` has too.
 float dCur = depthCur.Load(int3(p,0)).r;
 depthDst[p] = dCur;
 {
  // Written here with the depth history, before any branch, so it stays valid on every
  // dispatch whichever path returns - the same guarantee dst and depthDst already have.
  float2 mNow = mv.Load(int3(p,0)).xy * float2(mvScaleX, mvScaleY);
  mvDst[p] = all(isfinite(mNow)) ? mNow : float2(0.0, 0.0);
 }
 // Edit accumulation never passes a frame through: its reset frame is `histless` below and
 // still writes the raw history and a state, so the frame after a reset has something to test
 // against; and on danielblnc its `c` is not what it shows (it shows raw + edit).
 const bool accumPath = interleaved > 0.5 && extraTemporal > 9.5;
 // A pass-through frame also empties the residual it would have written. Skipping that write
 // is how a preset switch flashed: the restart frame left the buffer the NEXT frame reads
 // holding whatever the previous preset stored two frames earlier - after 10 -> 6 or 10 -> 8,
 // Edit accumulation's gain/slope state, read by v2 as a tonal edit (rawPrev = mean - edit),
 // so its raw-vs-raw test failed across the frame and the first filled frame showed raw.
 if (!accumPath && (reset!=0 || alpha<=0.0 || !all(isfinite(c.rgb)))) { dst[p]=c; residDst[p]=0.0; return; }
 int2 mx = int2(int(w)-1,int(h)-1);
#if !EDIT_ACCUM
 // Variance clip computed in a tonemapped domain (tm(x)=x/(1+x)) so bright HDR
 // lights are not statistical outliers - clipping them in linear space is what
 // made car/street lights flicker. Stats and the clip run in tm space; the chosen
 // colour is converted back with itm.
 float3 m1 = 0.0, m2 = 0.0, nmin = 1e30, nmax = -1e30;
 [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++) {
  float3 n = tmap(cur.Load(int3(clamp(p+int2(i,j), int2(0,0), mx),0)).rgb);
  m1 += n; m2 += n*n; nmin = min(nmin,n); nmax = max(nmax,n);
 }
 float3 mean = m1 * (1.0/9.0);
 float3 sigma = sqrt(max(m2 * (1.0/9.0) - mean*mean, 0.0));
 const float g = 1.25;                 // clip tightness: lower = less ghosting
 float3 lo = max(mean - g*sigma, nmin);
 float3 hi = min(mean + g*sigma, nmax);
#endif
 // VELOCITY DILATION - FSR2's FindNearestDepth, and the piece this pass never had.
 //
 // Every reprojection here used the pixel's OWN motion vector. FSR2 uses the vector of the
 // NEAREST-to-camera pixel in a 3x3 instead, and the difference is exactly the ghost of a
 // car smeared onto the road beside it.
 //
 // Take a road pixel sitting against the car's silhouette. Its own vector is the road's, so
 // it reprojects backwards along the road - and lands on where the CAR was, and comes back
 // with car colour. Every frame, along the whole edge. That is the doubled body in the
 // screenshot, and no depth test catches it: the test compares the two depths and correctly
 // reports a disocclusion, but by then the damage is in choosing the vector, not in reading
 // the colour. Rejecting after the fact leaves a hole; dilating first means the pixel never
 // asks the wrong question.
 //
 // With dilation that pixel borrows the car's vector, moves with the car, and the silhouette
 // stays whole. The cost is that a one-pixel band of background travels with the foreground,
 // which is invisible next to a second copy of the car.
 int2 mvSrc = p;
 // How much the depth already varies across this pixel's own neighbourhood. Free here -
 // the dilation loop is loading all nine samples anyway - and it is what makes the
 // disocclusion test below mean the same thing on hair as it does on a wall.
 float dNear = 1e30, dFar = -1e30;
 {
  float bestD = dCur;
  [unroll] for (int dy = -1; dy <= 1; ++dy)
  [unroll] for (int dx = -1; dx <= 1; ++dx)
  {
   int2 q = clamp(p + int2(dx, dy), int2(0,0), mx);
   float dq = depthCur.Load(int3(q,0)).r;
   if (!isfinite(dq)) continue;
   dNear = min(dNear, dq); dFar = max(dFar, dq);
   // "Nearest" depends on the convention the game hands us, which is why depthInv is a
   // constant rather than an assumption - getting it backwards would dilate toward the
   // FURTHEST surface and make this worse than doing nothing.
   bool nearer = (depthInv > 0.5) ? (dq > bestD) : (dq < bestD);
   if (nearer) { bestD = dq; mvSrc = q; }
  }
 }
 // DEPTH SPREAD, and this is the hair fix.
 //
 // The disocclusion test asks whether this pixel's depth moved more than a tolerance since
 // last frame. On a wall that question is meaningful. On HAIR it is not: a strand is
 // sub-pixel, so which surface a pixel lands on flips between the strand and whatever is
 // behind it from one frame to the next without anything being disoccluded at all. The
 // depth difference is large, the tolerance is fixed, and the test fires - constantly, on
 // every hair pixel, every filled frame.
 //
 // What it fires INTO is why it is visible: a rejected pixel falls back to a blurred copy
 // of the current frame, while a model frame shows the model's sharp output. So hair
 // alternates between sharp and blurred at the cadence, which is exactly the report.
 //
 // Same correction as the colour bound: a tolerance has to be measured in what this
 // neighbourhood already does. Where nine neighbouring depths disagree wildly - hair,
 // foliage, chain-link, foam - a depth change of the same size is not evidence of
 // anything, and the test has to demand much more before it rejects. On a flat surface the
 // spread is near zero and the tolerance is unchanged, so nothing this fixed gets weaker.
 float depthSpread = (isfinite(dNear) && isfinite(dFar)) ? max(dFar - dNear, 0.0) : 0.0;
 float2 m = mv.Load(int3(mvSrc,0)).xy * float2(mvScaleX, mvScaleY);
 bool mvBad = !all(isfinite(m)) || max(abs(m.x), abs(m.y)) > float(h) * 0.075;
 // ADAPTIVE INTERLEAVE, the measurement half. Interleave's ghosts and flicker only exist on
 // frames the model skipped, and only where the picture changed since the model last ran.
 // Where nothing moves a skipped frame is the model frame to within a quarter of a code
 // value (measured: 0.6/255 in Silent Hill 2 standing still). So: count the moving pixels
 // here (dword 1) and the fallbacks below (dword 0); the host runs the model every frame
 // while either is high and interleaves again when the picture settles.
 // Only FAST motion counts here (over six pixels a frame): ordinary camera and character
 // motion reprojects correctly and is exactly what interleave is for. Fast motion is where
 // reprojection errors and disocclusions get large, and where the first version's one-pixel
 // threshold left the model running every frame in normal play ("same fps as without it").
 if (interleaved > 0.5 && ((p.x | p.y) & 1) == 0 && all(isfinite(m)) && dot(m, m) > 36.0)
  changeCount.InterlockedAdd(4, 1u);
 // A SECOND, far looser bound, for the presets that reject on geometry alone.
 //
 // mvBad above is 7.5% of screen height - 85 pixels at 1139 - and it is right for what it
 // was written for: it feeds Standard's trust falloff, where a long vector should lower
 // confidence gradually. It is wrong as a HARD REJECT, which is how Held frame and
 // Residual temporal use it, because at 108 mph most of the road exceeds 85 pixels in a
 // frame. Those vectors are not wrong. They are long, and the road really did move that
 // far. Rejecting them threw the history away across half the screen, so half the frames
 // showed un-denoised asphalt next to denoised asphalt - a texture pulsing at the cadence,
 // which is the cloudy, dirty-looking road that no wording quite fits.
 //
 // What a hard reject is actually for is NONSENSE: the AMD optical flow returning tens of
 // thousands of pixels on flat dark areas, which the dlss5-neural-amd notes document and
 // guard against the same way. Half the screen height catches that and nothing else - no
 // camera moves half a screen in one frame and expects temporal anything to survive.
 bool mvInsane = !all(isfinite(m)) || max(abs(m.x), abs(m.y)) > float(h) * 0.5;
 // TEMPORAL MOTION DIVERGENCE, hoisted so every preset can use it.
 //
 // It lived inside Standard, which meant Held frame - the default, and the one the
 // ghosting reports are about - had only the depth reject. Depth cannot see this case:
 // a taillight's glow is painted over ROAD pixels and carries the road's depth, so
 // geometry says the surfaces match when they do not.
 //
 // This asks a different question, and it is the only one that answers. Follow the pixel's
 // vector back, and read the vector that was at that place a frame ago. A road pixel
 // trailing the car has a long vector and lands on the car, which does not move in screen
 // space at all - so the pixel claims to have come from somewhere that was standing still.
 // That is a contradiction, and taking the colour there is how the streak gets seeded.
 //
 // It is MOTION against MOTION. No colour is consulted, so the answer does not depend on
 // whether the model ran this frame - which is what makes it safe here, where every colour
 // test would have produced the cadence flicker instead.
 float mvDiverge = 0.0;
 {
  float2 backD = float2(p) + 0.5 + m + jit;
  float2 uvD = clamp(backD, float2(0.5, 0.5), float2(float(w), float(h)) - 0.5)
             / float2(float(w), float(h));
  float2 mPrevD = mvHist.SampleLevel(samp, uvD, 0);
  float lenD = length(m);
  if (lenD > 1.0 && all(isfinite(mPrevD)))
  {
   float ratio = saturate(length(mPrevD) / max(lenD, 1e-4));
   float ramp = saturate(pow(lenD / 20.0, 3.0));
   mvDiverge = lerp(0.0, 1.0 - ratio, ramp);
  }
 }

 // ====================== RESIDUAL TEMPORAL (no interleave) =======================
 // The model runs every frame here, so there is no gap to fill - this smooths the model's
 // EDIT over time instead, and leaves the picture strictly alone.
 //
 // The reason to want that: the network re-decides a pixel from scratch on every call, and
 // on emissive content its answer moves between calls even when the scene does not. That
 // is the flicker this file spent days on. Averaging the PICTURE to damp it is what makes
 // ghosts, because averaging a picture means showing an old one. Averaging only the
 // CORRECTION damps exactly the same jitter and cannot ghost: every pixel of geometry on
 // screen is this frame's, always, at full detail. The worst a wrong average can do is get
 // the model's polish slightly wrong on a pixel that is otherwise correct.
 //
 // Disocclusion is decided on depth, never colour, for the same reason as everywhere else
 // in this file: a colour test compares a denoised frame against an un-denoised one and
 // answers differently depending on which it got.
 // (Not in the EDIT_ACCUM build: it never runs under interleave.)
#if !EDIT_ACCUM
 if (residualTemporal > 0.5 && interleaved == 0.0)
 {
  float3 baseLin = base.Load(int3(p,0)).rgb;
  if (!all(isfinite(baseLin))) baseLin = c.rgb;
  float3 residNow = c.rgb - baseLin;
  float2 pvR = float2(p) + 0.5 + m + jit;
  float2 uvR = clamp(pvR, float2(0.5,0.5), float2(float(w), float(h)) - 0.5) / float2(float(w), float(h));
  float keep = 0.0;
  float3 carried = float3(0.0,0.0,0.0);
  if (!mvInsane)
  {
   float dPrev = depthHist.SampleLevel(samp, uvR, 0).r;
   bool ok = true;
   if (isfinite(dPrev))
   {
    float tol = max(max(dCur, dPrev) * 0.05, 0.0015);
    ok = abs(dCur - dPrev) <= tol;
   }
   if (ok)
   {
    float3 r = residHist.SampleLevel(samp, uvR, 0).rgb;
    if (all(isfinite(r))) { carried = r; keep = saturate(alpha); }
   }
  }
  // BOUND THE CARRIED EDIT AGAINST THIS FRAME'S EDIT.
  //
  // The claim at the top of this block - that averaging only the correction cannot ghost -
  // is true about the PICTURE and false about the correction itself, and a report from GTA
  // V is what showed the difference: a dark smear trailing the car along the road, looking
  // like a reflection of it.
  //
  // The mechanism is the same one as the smoke ghost in Held frame. A car's contact shadow
  // is screen-space content sitting on road pixels, so it carries the ROAD's motion
  // vectors, not the car's. The shadow moves with the car; its vectors say it moved with
  // the road. So its edit reprojects backwards along the tarmac, and because the blend
  // writes its own result back as the next frame's history, each frame re-averages that
  // stale dark edit in at `keep` and lays down a little more of it. Depth cannot object -
  // the road behind a car is continuous, every vector is finite and smooth.
  //
  // What CAN object is this frame's own edit. `residNow` is the model's answer for this
  // exact pixel, computed this frame; if the carried edit disagrees with it by many times
  // its own size, the history is describing different content that happened to land here.
  //
  // And comparing them is not the colour test this file forbids elsewhere. That rule is
  // about comparing a denoised frame against an un-denoised one, which answers differently
  // depending on which frame type it got. Both sides here are the model's own output, on
  // the same kind of frame - the model runs every frame in this mode - so there is no
  // cadence for the answer to alternate with.
  //
  // Scaled as one triple by a single scalar, never per channel: a per-channel clamp lets
  // whichever channel is furthest out decide the hue of the rest.
  {
   float3 dR = carried - residNow;
   float dm = max(abs(dR.x), max(abs(dR.y), abs(dR.z)));
   float cur = max(abs(residNow.x), max(abs(residNow.y), abs(residNow.z)));
   // Allowed disagreement: as much again as the model is already changing here, plus a
   // small floor so a pixel the model is barely touching this frame can still receive
   // some smoothing. Where the model makes a big, consistent edit `cur` is large and this
   // does nothing; where it makes almost none, a large carried edit is not smoothing, it
   // is a leftover.
   float lim = cur + residualCap * 0.1 + 0.002;
   // #5: on a pixel that has not moved, widen the allowed disagreement by the still-surface floor.
   [branch] if (staticRelax > 0.0 && !mvBad && keep > 0.0) {
    float dPS = depthHist.SampleLevel(samp, uvR, 0).r;
    lim = stillLimit(lim, dm, baseLin, saturate(staticRelax) * stillWeight(p, m, pvR, dCur, dPS, max(max(dCur, dPS) * 0.05, 0.0015)));
   }
   if (isfinite(dm) && dm > lim) carried = residNow + dR * (lim / dm);
  }
  float3 blended = fitResidual(baseLin, boundResidual(lerp(residNow, carried, keep), baseLin, residualCap));
  residDst[p] = float4(blended, 0.0);
  // max(0) because a negative colour is not a colour. The sum can go under zero where a
  // carried edit is darker than the pixel it lands on, and a negative channel reaching the
  // upscaler is undefined behaviour dressed up as data.
  dst[p] = float4(baseLin + blended, c.a);
  return;
 }
#endif

 // =========================== MODEL INTERLEAVE ===============================
 // Everything about interleave is in this block, and nothing outside it knows the
 // feature exists. Both frame types - the ones the model ran on and the ones it
 // skipped - go through this identical code with identical constants.
 //
 // THE DESIGN RULE, which is the conclusion of rewriting this path many times:
 // EVERY PIXEL IS PRODUCED BY ONE FORMULA, AND VALIDITY IS A WEIGHT, NEVER A
 // DIFFERENT IMAGE. Each earlier version had escape hatches - "if the history is
 // off-screen / disoccluded / disagrees, show something else instead" - and every
 // one of them drew a visible border wherever its condition flipped:
 //   - at silhouettes, where a depth test flipped on a different scatter of pixels
 //     each frame, it showed as sparkle;
 //   - across the bottom of the screen, where forward motion sends a whole band of
 //     reprojections past the edge at once, it showed as the road appearing cut off;
 //   - between a model frame and a skipped frame, it showed as flicker.
 // So: no early returns, no fallback colour, no second source. Weights only.
 //
 // WHY THE BANDS ARE SPLIT. Measured on a real driving capture of this game: the
 // cadence-locked component of what arrives here is 0.01614 full-band and 0.01232
 // after blurring - 76% of the model-vs-skip difference SURVIVES a blur. The model
 // is not just removing grain, it re-renders: it changes brightness and tone over
 // broad areas. That single number is why ten rounds of tuning could not win. Any
 // fill that reads the current frame carries that broad change and flickers; any
 // fill that refuses to read it has nothing to place detail with and ghosts. Both
 // are unavoidable only while the frame is treated as one signal. Split it, and
 // each band has an unambiguous best source:
 //   LOW  band  <- reprojected history. This is where the model's re-rendering
 //                 lives, so taking it from the denoised side is what makes a
 //                 skipped frame look like a model frame. No cadence.
 //   HIGH band  <- the CURRENT frame, always, at full spatial accuracy. Detail
 //                 belongs where the geometry is THIS frame, so nothing sharp can
 //                 be dragged in from where an object used to be. No ghost.
 // A ghost surviving in the low band is a soft tint, not a doubled edge, and the
 // bound below limits it. The cost is grain, because the high band of an
 // un-denoised frame is partly noise - `detailScale` trades that against sharpness
 // and cannot affect the cadence, because it never touches the low band.
 // MODEL-FRAME GHOST METER (dwords 4/5). The question every fill-side fix so far could not
 // answer: is the ghost in the MODEL'S OWN frames? Under interleave the network used to run
 // its temporal path on a history two frames old; a ghost it builds there is ground truth
 // to everything downstream, and no fill can learn it away - a learner copies its teacher.
 // So, on model frames, among moving pixels whose old content differs from the new raw,
 // count those where the model's answer looks more like the OLD picture at this position
 // than like the raw it was handed. Read in the menu as 'Model-frame ghost'.
 // (The EDIT_ACCUM build runs this test inside its block, where the fit already has the model's
 // local variance: see GHOST METER there.)
#if !EDIT_ACCUM
 if (interleaved > 0.5 && modelFrame > 0.0 && ((p.x ^ p.y) & 1) == 0 && all(isfinite(m)) && dot(m, m) > 4.0)
 {
  float3 rawM = tmap(base.Load(int3(p,0)).rgb);
  float3 oldM = tmap(hist.Load(int3(p,0)).rgb);
  float3 newM = tmap(c.rgb);
  const float3 lw = float3(0.2126, 0.7152, 0.0722);
  float eRaw = dot(abs(newM - rawM), lw), eOld = dot(abs(newM - oldM), lw), eSep = dot(abs(rawM - oldM), lw);
  float nfM = dot(sigma, lw) + 0.01;
  if (isfinite(eRaw) && isfinite(eOld) && isfinite(eSep) && eSep > 2.0 * nfM)
  {
   changeCount.InterlockedAdd(20, 1u);
   if (eRaw > nfM && eOld < 0.5 * eRaw) changeCount.InterlockedAdd(16, 1u);
  }
 }
#endif
 // The EDIT_ACCUM build is this block and nothing after it; the ordinary build is everything
 // after it and not this block (the host picks the pipeline by the same test the block makes).
#if EDIT_ACCUM
 // ======================= EDIT ACCUMULATION (presets 10 and 11) ========================
 // One branch for both runtimes and both frame types: 10 = danielblnc, 11 = lmxxf (the host
 // encodes the runtime in the preset number, so no constant or parameter was added for it).
 //
 // WHAT IT REMOVES. The owner's report (2026-09-26): with Model interleave on, ghosting and
 // flicker remain - slight on lmxxf, clearly visible on danielblnc. The danielblnc half has a
 // measured cause. Guided fill v2's filled frame shows the PREVIOUS MODEL PICTURE, reprojected
 // and Catmull-Rom resampled: a one-frame ghost wherever the vectors do not describe the
 // content, and a high band (grain, sparkle, the jitter sample itself) that refreshes at half
 // the frame rate - the filled frame's high band correlated 0.83-0.91 with the previous model
 // frame (handoff 2638ae69), and the upscaler was handed the same jitter sample twice. Its
 // model frames were written straight through, undamped, so the network's per-call
 // re-decision showed as an A A B B square wave; its fallbacks ran on filled frames only; and
 // its ghost test (tRaw) compared a nearest-texel 3x3 mean against a Catmull-Rom edit -
 // misregistered by construction - with a tolerance that included a fifth of the local range.
 //
 // THE RULE HERE: every frame on both runtimes is THIS FRAME'S RAW plus a carried LOCAL
 // CORRECTION. No picture ever travels, so the high band on screen is always the current one
 // and no object can be dragged to where it used to be. What travels is a local linear model
 // of what the network did (danielblnc: a per-channel gain of the local mean and a luminance
 // slope on this frame's own detail, fitted on model frames - the guided filter's local-linear
 // fit, He/Sun/Tang 2010), or the edit itself (lmxxf, as preset 9 carries it).
 //
 // Validity is decided ONCE, by the same code on both frame types: geometry (depth,
 // divergence, reactive, insane vectors - preset 9's guards) times a RAW AGAINST RAW test -
 // a 1-2-1 tent of this frame's raw against the same tent of the previous frame's raw at the
 // reprojected position, relative (YCoCg over luma, so it means the same at 0.15 and at 1500),
 // with a tolerance learned per pixel from the temporal noise where the carry was trusted.
 // Static texture cancels out of that test, grain is what it learns, and a different surface
 // fails it. Where it fails, BOTH frame types show the same position-free prior - the model's
 // per-luminance gain from the log LUT, and on danielblnc its per-luminance detail ratio for
 // this frame's own detail - which cannot ghost and does not pulse.
 //
 // Damping across model calls is Temporal stability, in TRANSFORM space (gain/slope are
 // EMA'd, never pixels: the 217be265 lesson), with lmxxf's agreement clamp in output space.
 // Each fresh answer is spread over two frames - half on the frame it arrives, half on the
 // next - so nothing steps at 30 Hz, and `keep` is never compounded into the stored state.
 //
 // WHAT IT COSTS, and why the model's own high band is not carried to buy it back. A danielblnc
 // model frame shows the fitted, damped correction too, not the model's exact picture: it has to,
 // or the part the fit misses would be on screen on every other frame only - a 30 Hz alternation
 // of exactly the fine detail the eye reads. On a real Forza capture (raw and answer on every
 // frame) a fresh fit reproduced about 55% of the model's local change (tonemapped luminance,
 // 0.0176 of the mean away from the answer where the raw is 0.0391). The model does NOT denoise
 // the fine band there or in Silent Hill 2 (Forza: high band 1.05x the raw's, correlation
 // 0.91-0.94; SH2: 0.95x, handoff 2638ae69), so the grain the fit keeps is the grain the model
 // shows too; a synthetic model that removes all grain is what makes this path look grainy.
 // Carrying the model's high band instead (the "detail term") was measured on the same capture
 // with optical flow for vectors: a filled frame 0.087-0.100 away from the model's real answer
 // against 0.039 for this path and 0.151 for the held picture without its guards - a reprojected
 // high band lands a fraction of a pixel off on a frame that has its own, the rule the owner's
 // "strange, ugly" v2 and the removed carried-high-band build (febac76b) already taught. Where a
 // picture should be literal - Network output, the Look and lighting Inspect views - Model
 // interleave has to be off.
 if (interleaved > 0.5 && extraTemporal > 9.5)
 {
  const bool dan = extraTemporal < 10.5;                 // 10 = danielblnc, 11 = lmxxf
  // reset 1: no history at all (first frame, cut, resize, a restart). reset 2: the carried state
  // is valid but there is no raw history to test it against - lmxxf coming from Classic carry (9),
  // which stores the same linear edit and no raw, or a raw history allocated this frame. That
  // frame trusts the geometry alone, as preset 9 always did, and writes the raw the next tests.
  const bool histless = reset == 1u;
  const bool rawMissing = reset == 2u;
  const float2 wh = float2(float(w), float(h));
  const float3 lwA = float3(0.2126, 0.7152, 0.0722);
  // danielblnc: the model answered THIS frame, at p, in `cur` (a refused Record comes in as a
  // filled frame, modelFrame 0). lmxxf: the answer of frame N-1 arrived, in `base` (t6), in
  // frame N-1's pixel space - the network is always a frame late there.
  const bool freshHere = dan && modelFrame > 0.5;
  const bool freshLate = !dan && residualTemporal > 0.5;
  // This frame's raw: the pre-model copy on danielblnc (bound as t6 on both frame types for
  // this preset), the frame itself on lmxxf (the edit is added here, never inside the runtime).
  float3 R = dan ? base.Load(int3(p,0)).rgb : c.rgb;
  if (!all(isfinite(R))) { dst[p] = c; residDst[p] = 0.0; rawDst[p] = 0.0; return; }
  R = max(R, 0.0);
  // 1. A 3x3 tent (1-2-1) of this frame's raw, and on a danielblnc model frame of the answer as
  //    well, with luminance sums centred on this pixel so the variance keeps its precision at
  //    four-figure scene values. The tent, not a box: the previous raw is read below as four
  //    bilinear taps at pv +- 0.5, which IS the same tent at a fractional position, so the two
  //    sides of the test are the same filter at exactly corresponding points.
  const float lC = dot(R, lwA);
  float3 mR = 0.0, mM = 0.0; float wS = 0.0, sR = 0.0, sRR = 0.0, sM = 0.0, sRM = 0.0, sMM = 0.0;
  [unroll] for (int ja = -1; ja <= 1; ++ja) [unroll] for (int ia = -1; ia <= 1; ++ia) {
   const int3 q = int3(clamp(p + int2(ia, ja), int2(0,0), mx), 0);
   const float wt = (ia == 0 ? 0.5 : 0.25) * (ja == 0 ? 0.5 : 0.25);
   float3 rq = dan ? base.Load(q).rgb : cur.Load(q).rgb;
   float3 mq = freshHere ? cur.Load(q).rgb : rq;
   if (!all(isfinite(rq)) || !all(isfinite(mq))) continue;
   rq = max(rq, 0.0); mq = max(mq, 0.0);
   const float lr = dot(rq, lwA) - lC, lm = dot(mq, lwA) - lC;
   wS += wt; mR += wt*rq; sR += wt*lr; sRR += wt*lr*lr; mM += wt*mq; sM += wt*lm; sRM += wt*lr*lm; sMM += wt*lm*lm;
  }
  if (wS > 0.0) { const float iw = 1.0/wS; mR *= iw; mM *= iw; sR *= iw; sRR *= iw; sM *= iw; sRM *= iw; sMM *= iw; } else { mR = R; mM = R; }
  const float LmR = max(dot(mR, lwA), 0.0);
  // The offset that makes the gain exact at the fit and scale-invariant: 5% of the local mean.
  const float eps = 0.05 * LmR + 1e-9;
  const float varR = max(sRR - sR*sR, 0.0);
  // GHOST METER (dwords 4/5), this build's form of the test before this block: the same three
  // distances on the same sampled moving pixels of model frames, with the noise floor taken from
  // the model's own tent variance the fit has just summed (luminance, mapped through the tonemap's
  // slope at the local mean) instead of from 3x3 statistics this build no longer computes. That
  // extra 3x3 cost 0.04 ms of a 2560x1440 model frame in motion. And it samples one 8x8 group in
  // four (every fourth row and column inside it), not every other pixel: the meter is a ratio of
  // two counts, ~57,000 candidates at 2560x1440 are plenty, and the previous output it alone reads
  // was a fetch whose latency every wave then waited on at the end of the pass (0.03 ms more).
  if (freshHere && ((p.x | p.y) & 3) == 0 && (((p.x >> 3) + (p.y >> 3)) & 3) == 0 && all(isfinite(m)) && dot(m, m) > 4.0)
  {
   const float3 rawM = tmap(R);
   const float3 oldM = tmap(hist.Load(int3(p,0)).rgb);
   const float3 newM = tmap(max(c.rgb, 0.0));
   const float eRaw = dot(abs(newM - rawM), lwA), eOld = dot(abs(newM - oldM), lwA), eSep = dot(abs(rawM - oldM), lwA);
   const float LmM0 = max(dot(mM, lwA), 0.0);
   const float nfM = sqrt(max(sMM - sM*sM, 0.0)) / ((1.0 + LmM0) * (1.0 + LmM0)) + 0.01;
   if (isfinite(eRaw) && isfinite(eOld) && isfinite(eSep) && isfinite(nfM) && eSep > 2.0 * nfM)
   {
    changeCount.InterlockedAdd(20, 1u);
    if (eRaw > nfM && eOld < 0.5 * eRaw) changeCount.InterlockedAdd(16, 1u);
   }
  }
  // 2. Validity of the carried state: geometry x raw against raw.
  //    The real vector up to half the screen (mvInsane), never zeroed at 7.5% of the height the
  //    way `mvBad` does - at speed most of the road exceeds that and is not wrong - and no
  //    static-position pick (pvStatic): a wrong pick there IS a ghost, and the raw test below
  //    now answers that question for every pixel instead.
  const float2 pvA = clamp(float2(p) + 0.5 + (mvInsane ? float2(0.0,0.0) : m) + jit, float2(0.5,0.5), wh - 0.5);
  // First guess at the relative temporal noise, until the pixel has learned its own: the
  // variance of a difference of two independent tents (2 x 0.1406) of this local variance.
  const float nuInit = 0.28 * varR / max(LmR*LmR, 1e-12);
  float keepGeo = 0.0, gate = 0.0, nuN = nuInit;
  if (!histless) {
   float occ = 0.0;
   const float dPrev = depthHist.SampleLevel(samp, pvA / wh, 0).r;
   if (isfinite(dPrev)) {
    // The 0.0015 absolute floor of the other presets swallowed reverse-Z's whole far range
    // (distant depths there live below 0.001), so the depth test never fired at a distance.
    const float depthAbsFloor = depthInv > 0.5 ? 1e-5 : 0.0015;
    const float tolD = max(max(max(dCur, dPrev) * 0.05, depthAbsFloor), depthSpread * 0.75);
    occ = saturate((abs(dCur - dPrev) - tolD) / max(tolD, 1e-6));
   }
   if (mvInsane) occ = 1.0;
   keepGeo = 1.0 - max(occ, max(mvDiverge, reactiveAt(p)));
   gate = 1.0;
   if (!rawMissing) {
   float4 tP = 0.0;   // 4 bilinear taps at pv +- 0.5 = the same 1-2-1 tent, of the previous raw
   [unroll] for (int kt = 0; kt < 4; ++kt)
    tP += rawHist.SampleLevel(samp, (pvA + float2((kt & 1) ? 0.5 : -0.5, (kt & 2) ? 0.5 : -0.5)) / wh, 0);
   tP *= 0.25;
   const float3 yN = toYCoCg(mR), yP = toYCoCg(max(tP.rgb, 0.0));
   const float dRel = amax3(abs(yN - yP)) / (0.5 * (yN.x + yP.x) + 1e-6);   // relative: any scene magnitude
   const float nuP = (isfinite(tP.a) && tP.a > 0.0) ? tP.a : nuInit;
   // Three sigma of what this pixel's raw normally wanders by between frames, plus 4% for the
   // sub-pixel jitter that survives the tent. A ramp to full refusal at 1.5x, never a switch.
   const float tolR = 3.0 * sqrt(nuP) + 0.04;
   gate = (isfinite(dRel) && all(isfinite(tP.rgb))) ? 1.0 - saturate((dRel / tolR - 1.0) * 2.0) : 0.0;
   // Learned only where the carry is trusted, and bounded to 4x per step, so one frame of a
   // different surface cannot teach the pixel to accept the next one.
   if (keepGeo * gate > 0.5) nuN = lerp(nuP, min(dRel*dRel, 4.0*nuP + 0.0016), 0.25);
   }
  }
  const float keep = keepGeo * gate;
  // The raw history is written before anything below can return, so it is valid on every
  // dispatch - the guarantee dst, depthDst and mvDst have.
  rawDst[p] = float4(min(R, 65000.0), isfinite(nuN) ? min(nuN, 65000.0) : 0.0);
  // 3. The prior: the model's per-luminance gain, position-free (it cannot ghost). What BOTH
  //    frame types show wherever the carried state is not valid.
  //    danielblnc's prior keeps this frame's own detail at the model's measured detail ratio for
  //    this brightness (lutDetailLog), not at the tone gain: the tone gain alone handed a refused
  //    region the raw's full grain even where the model removes it, and a softer texture than
  //    the model's where it sharpens - a patch of a different KIND of picture, on both frame
  //    types, wherever the reactive mask, a disocclusion or the raw test refused the carry
  //    (synthetic, carry refused everywhere: high-band error against the model -28% for a model
  //    that keeps grain, -14% for one that removes it, -70% for one that sharpens 1.8x).
  //    Position-free like the gain, so it cannot ghost either. lmxxf keeps the tone gain.
  const float gLut = lutGainLog(LmR);
  const float4 Sprior = dan ? float4((gLut*mR + eps) / (mR + eps) - 1.0, lutDetailLog(LmR) - 1.0) : float4((gLut - 1.0) * R, 0.0);
  // 4. The carried state and, when an answer arrived, the fresh one.
  float4 SP = Sprior;
  if (keep > 0.0) { const float4 r4 = sampleResid4(pvA); if (all(isfinite(r4))) SP = dan ? r4 : float4(r4.rgb, 0.0); }
  const bool fresh = freshHere || freshLate;
  float4 SF = Sprior;
  if (freshHere) {
   // The fit, per pixel over the tent: a gain per channel for the local mean, and the
   // least-squares slope of the model's luminance on the raw's for the detail, regularised
   // toward the gain (lam, 2% of the mean) so flat regions - where the slope is undetermined
   // and would otherwise amplify grain - take the tone and leave the texture alone.
   const float LmM = max(dot(mM, lwA), 0.0);
   const float3 Gf = clamp((mM + eps) / (mR + eps), 1.0/16.0, 16.0);
   const float gL = clamp((LmM + eps) / (LmR + eps), 1.0/16.0, 16.0);
   const float lam = (0.02 * (LmR + eps)) * (0.02 * (LmR + eps));
   const float Af = clamp((sRM - sR*sM + lam*gL) / (varR + lam), 0.0, 4.0);
   SF = float4(Gf - 1.0, Af - 1.0);
   if (!all(isfinite(SF))) SF = Sprior;
  } else if (freshLate) {
   // lmxxf: the fresh edit is in frame N-1's space; carried here by the same position and the
   // same validity as the state, and the prior where that validity fails.
   const float3 fr = sampleBaseCR(pvA);
   SF = float4(all(isfinite(fr)) ? lerp(Sprior.rgb, fr, keep) : Sprior.rgb, 0.0);
  }
  // 5. Damp across model calls and spread each answer over two frames.
  //    The carried state may not pull the fresh answer further than the fresh answer's own
  //    size (plus 5% of the pixel) - lmxxf's agreement clamp, measured on the OUTPUT so the
  //    gain/slope form is judged by what it would show. Then the EMA at Temporal stability.
  //    The fresh frame shows half the step; the next frame shows the rest (it shows SP = acc).
  float4 acc, shown; float3 oF = R;
  if (fresh) {
   oF = accumOut(SF, dan, R, mR, eps);
   const float3 oP = accumOut(SP, dan, R, mR, eps);
   const float dm = amax3(abs(oP - oF));
   const float lim = amax3(abs(oF - R)) + 0.05 * amax3(R) + (dan ? 1e-6 : 0.002);
   const float4 Pc = (isfinite(dm) && dm > lim) ? SF + (SP - SF) * (lim / dm) : SP;
   acc = lerp(SF, Pc, saturate(alpha) * keep);
   shown = histless ? acc : 0.5 * (Pc + acc);
  } else {
   // No answer: carry the state once more. An invalid carry decays to the prior, and the
   // stored state never has `keep` multiplied into it - preset 9 did, and a pixel at keep 0.8
   // lost a fifth of its edit on every frame it was carried.
   acc = lerp(Sprior, SP, saturate(2.0 * keep));
   shown = SP;
  }
  const float4 Sd = histless ? shown : lerp(Sprior, shown, keep);
  const float3 eA = fitResidual(R, boundResidual(accumOut(Sd, dan, R, mR, eps) - R, R, residualCap));
  if (!all(isfinite(acc))) acc = Sprior;
  // lmxxf keeps preset 9's residual convention - a linear edit, bounded, alpha = the geometric
  // keep - so its stats line and self-heal read the same quantity they always did.
  residDst[p] = dan ? acc : float4(fitResidual(R, boundResidual(acc.rgb, R, residualCap)), keepGeo);
  // Counters, at a quarter of the pixels: dword 0 = the prior (tone curve) is what is shown,
  // 12 = refused by the raw test alone (geometry fine), 10/11 = on danielblnc model frames, how
  // much of the model's local detail the fit missed / how much there was in total.
  if (((p.x | p.y) & 1) == 0) {
   if (keep < 0.5) changeCount.InterlockedAdd(0, 1u);
   if (keepGeo > 0.5 && gate < 0.5) changeCount.InterlockedAdd(48, 1u);
   if (freshHere) {
    const float lc = dot(tmap(max(c.rgb,0.0)), lwA), lf = dot(tmap(max(oF,0.0)), lwA), lb = dot(tmap(mM), lwA);
    if (isfinite(lc) && isfinite(lf) && isfinite(lb)) {
     changeCount.InterlockedAdd(40, uint(saturate(abs(lc - lf)) * 4096.0));  // model detail the fit missed
     changeCount.InterlockedAdd(44, uint(saturate(abs(lc - lb)) * 4096.0));  // model detail in total
    }
   }
  }
  // Debug views. Every history (raw, state, depth, motion) is already written, so a view never
  // poisons the next frame the way the old overlays did.
  //  1 validity - white where the carried state is used, black where the tone curve is shown
  //  2 frame type - red where an answer arrived, blue where none did
  //  3 guards - red where the raw test refused, green where the geometry did
  //  4 raw where no fresh answer arrived - whatever still ghosts with this on is the model's
  //  5 edit size, x10 (danielblnc; lmxxf's 5 is the host's direct edit)
  if (debugView > 0.5 && debugView < 1.5) { dst[p] = float4(keep.xxx, c.a); return; }
  if (debugView > 1.5 && debugView < 2.5) { dst[p] = float4(fresh ? float3(1,0.1,0.1) : float3(0.1,0.3,1), c.a); return; }
  if (debugView > 2.5 && debugView < 3.5) { dst[p] = float4(1.0 - gate, 1.0 - keepGeo, 0.0, c.a); return; }
  if (debugView > 3.5 && debugView < 4.5 && !freshHere) { dst[p] = float4(R, c.a); return; }
  if (debugView > 4.5 && dan) { dst[p] = float4(abs(eA) * 10.0, c.a); return; }
  dst[p] = float4(R + eA, c.a);
  return;
 }
#else
 if (interleaved > 0.0) {
  // Debug view 4, 'Raw on skipped frames': no fill at all - a skipped frame IS the raw
  // frame. The only temporal thing left on screen is the model itself, so whatever still
  // ghosts or smears with this on is the model's, not this pass's.
  if (debugView > 3.5 && modelFrame <= 0.0) { dst[p] = c; residDst[p] = float4(0.0, 0.0, 0.0, 0.0); return; }
  // -- Reprojection. `prev` is CLAMPED into the frame, never tested and abandoned.
  //    Off-screen means this pixel's history left the frame; the nearest edge
  //    sample is the closest thing to it that still exists, and using it keeps the
  //    formula the same everywhere. This is what removes the line across the road.
  float2 prevI = float2(p) + 0.5 + (mvBad ? float2(0.0, 0.0) : m) + jit;
  float2 pv = clamp(prevI, float2(0.5, 0.5), float2(float(w), float(h)) - 0.5);
  // -- WHERE the history is, tested rather than assumed. EXTRA TEMPORAL only.
  //
  //    The buffer says this pixel came from `pv`. That is right for the surface the
  //    pixel belongs to, and wrong for anything that does not follow that surface. A
  //    taillight's glow is the case that has resisted everything: it is a screen-space
  //    effect stuck to a car that is STILL in screen space, so its true motion is zero,
  //    while the road it lies on races past. The road's vectors there are smooth and
  //    accurate - accurate FOR THE ROAD - so no test of the motion field can see the
  //    problem, and dragging the glow along them is the ghost.
  //
  //    But the two possibilities can be compared. Sample the history where the vector
  //    says, and again right here as if the pixel had not moved, and see which one
  //    actually resembles what is in front of us now.
  //
  //    What makes this different from every colour test that failed today: those
  //    compared the history against the current frame in absolute terms, and the model
  //    lifts brightness and saturation, so a good history looked wrong everywhere. Here
  //    both candidates are measured against the SAME reference, so that lift shifts
  //    both by the same amount and cancels out of the comparison. What survives is only
  //    the question being asked - which position was right - which the lift cannot bias.
  //
  //    The reprojected answer is preferred unless the static one is clearly better, so
  //    ordinary noise cannot flip the choice back and forth between frames.
  float3 loCurEarly = softCurTm(p, mx);
  if (extraTemporal >= 1.5)
  {
   float2 pvStatic = float2(p) + 0.5 + jit;
   float eMoved  = length(softHistTm(pv, mx)       - loCurEarly);
   float eStatic = length(softHistTm(pvStatic, mx) - loCurEarly);
   if (eStatic * 1.3 < eMoved) pv = pvStatic;
  }
  float3 hcolI = sampleHistory(pv);
  if (!all(isfinite(hcolI))) hcolI = hist.Load(int3(p,0)).rgb;  // still history, not `c`
  // -- Trust is GEOMETRIC only: how far this pixel reprojected. Colour evidence is
  //    deliberately not consulted. On a skipped frame the current frame is
  //    un-denoised and the model re-renders rather than merely denoising, so any
  //    test comparing the two is really measuring "was this a model frame" - and
  //    acting on that measurement is exactly how the cadence becomes visible.
  //    The falloff is smooth so the weight never snaps.
  //    The falloff starts from zero motion on purpose. Flattening it - trusting the
  //    history fully until the vector is nearly an outlier - was tried and brought the
  //    ghosting straight back: at an ordinary 20 px/frame it raised trust from 0.76 to
  //    1.00, which is a lot more history on exactly the moving content that smears.
  //    A reprojection is never perfectly reliable, so the weight should not pretend it
  //    is; it should fall off with how far the pixel actually travelled.
  // How far the reprojected history is trusted. The two presets split HERE, because
  // this is the one number the whole ghost-versus-grain trade runs through, and the two
  // reasonable answers to it are genuinely different products rather than a value to
  // tune between.
  //
  // STANDARD judges a vector by its LENGTH. The road ahead moves fast, so its vectors
  // are long, so trust falls to about 0.3 there and most of the picture comes from the
  // current frame. That costs sharpness and lets some of the un-denoised frame's grain
  // through - but it also means a wrong reprojection is corrected immediately instead
  // of being carried, which is why ghosting stays mild. This is the behaviour that has
  // been stable to look at all along.
  //
  // EXTRA TEMPORAL judges a vector by its local CONSISTENCY. A flat road at speed has
  // long but perfectly accurate vectors, so this keeps trust at 1 there and takes the
  // picture from the denoised history: sharper, and free of the current frame's grain.
  // Its weakness is content that does not follow the motion field it sits on - a
  // taillight's glow is a screen-space effect stuck to a car that is still in screen
  // space, lying on a road that is racing past, and the road's vectors there are smooth
  // and correct for the road while being completely wrong for the glow. No test of the
  // motion field can see that, because the field really is smooth; so the glow gets
  // dragged, and that is the heavy ghosting.
  // preset: 0 = Off, 1 = Standard, 2 = Extra temporal.
  float trust;
  if (extraTemporal < 1.5)
  {
   // Off and Standard share the length falloff. They differ only in the guard below,
   // so comparing them isolates exactly one thing.
   trust = mvBad ? 0.0 : saturate(1.0 - max(abs(m.x), abs(m.y)) / (float(h) * 0.075));

   // TEMPORAL MOTION DIVERGENCE - FSR2 ComputeTemporalMotionDivergence, and the one test
   // in this file that can actually see the taillight trail.
   //
   // The note above says no test of the motion field can catch it, because the field
   // really is smooth and really is correct for the road the glow lies on. That holds for
   // every test that looks at THIS frame's vectors. This one looks at LAST frame's.
   //
   // Follow the pixel's own vector back to where it came from, then read the vector that
   // was at that place a frame ago. A road pixel trailing the car has a long vector -
   // twenty-odd pixels of road flow - and following it lands on the car, which does not
   // move in screen space at all. So the pixel claims to have come from somewhere that was
   // standing still, and that is a contradiction: whatever sits at the source belongs to a
   // different surface, and taking its colour is exactly how the streak gets seeded. Kill
   // the seed and the streak cannot grow, because every later pixel of it is a copy of an
   // earlier one.
   //
   // Safe on everything else by construction. A pixel moving with the road finds the
   // road's own vector at the source, so the ratio is near one and nothing happens. A
   // static pixel - the car, its lights, the HUD - never passes the length gate. The cubic
   // ramp means motion under about twelve pixels is untouched, so this cannot dull slow
   // content, which is where every previous guard here did its damage.
   trust *= 1.0 - mvDiverge;
  }
  else
  {
   float2 mUp = mv.Load(int3(clamp(p + int2(0,-2), int2(0,0), mx),0)).xy * float2(mvScaleX, mvScaleY);
   float2 mDn = mv.Load(int3(clamp(p + int2(0, 2), int2(0,0), mx),0)).xy * float2(mvScaleX, mvScaleY);
   float2 mLf = mv.Load(int3(clamp(p + int2(-2,0), int2(0,0), mx),0)).xy * float2(mvScaleX, mvScaleY);
   float2 mRt = mv.Load(int3(clamp(p + int2( 2,0), int2(0,0), mx),0)).xy * float2(mvScaleX, mvScaleY);
   float disc = max(max(length(mUp - m), length(mDn - m)), max(length(mLf - m), length(mRt - m)));
   if (!all(isfinite(float4(mUp + mDn, mLf + mRt)))) disc = 1e9;
   trust = mvBad ? 0.0 : saturate(1.0 - disc / 2.0);
  }
  // -- Bound the history's low band by the colour that actually exists around this
  //    pixel, so a stale sample cannot tint the area arbitrarily. nmin/nmax rather
  //    than mean +/- k*sigma: an isolated bright pixel - a street light among dark
  //    neighbours - is a real feature, and the gaussian box calls it an outlier and
  //    crushes it to a few percent of its brightness on skipped frames only. That
  //    was measured as a 12x cadence-locked swing and was the light flicker.
  float3 loCur     = loCurEarly;
  float3 loHistRaw = softHistTm(pv, mx);
  // Bounded by the neighbourhood's absolute range ONLY. A tighter bound centred on
  // `loCur` was tried and had to come out: `loCur` is the UN-DENOISED frame, and the
  // model does not merely denoise - it re-renders, lifting brightness and saturation -
  // so centring the bound there drags every filled frame back toward the darker, flatter
  // un-denoised picture. In one direction, every frame. That is not flicker, it is a
  // permanent colour shift, and it is exactly the "interleave looks darker and less
  // saturated" difference. nmin..nmax is wide enough that it only catches a history
  // sample whose colour appears nowhere nearby, which is the ghost it exists for.
  // Bounded by a RATIO, in linear space. Once the debug overlay stopped poisoning its
  // own history, the clamp-activity view still came back red across the whole frame and
  // green only on high-frequency edges - the guard firing everywhere except the one
  // place ghosts actually live. Exactly inverted, and for two compounding reasons:
  //
  //   - `nmin`/`nmax` come from a 3x3. On a flat surface - road, sky, a wall - the nine
  //     samples agree, so the box has essentially ZERO width and any difference at all
  //     is clamped. On an edge the box is wide and nothing is clamped.
  //   - tm(x)=x/(1+x) compresses everything above ~100 into the last thousandth of its
  //     range, and this game's scene values run to four figures, so in tm space the
  //     whole box is about 1e-4 wide. There is no meaningful tolerance left to express.
  //
  // A ratio in linear space has neither problem: it does not collapse when neighbours
  // agree, and it does not shrink as the scene gets brighter. +/-40% is loose enough
  // that the model's own re-rendering passes untouched, and far tighter than what a red
  // taillight standing over grey asphalt needs to be caught by.
  // The two presets part company here, and NOWHERE else. Everything before and after
  // this block is identical in both, so a difference you can see between them comes
  // from this and only this.
  // ===================== WHAT A SKIPPED FRAME SHOWS =========================
  //
  // Presets 0 and 1 do NOT split the frame into bands. That split is where every
  // colour artefact in this file came from, and it took a long time to see why.
  //
  // The split reconstructs the picture as `lowBand + detail`, with the two halves
  // sourced and guarded differently - and the sum of two separately-processed halves
  // is not constrained to be a plausible colour at all. Guard one half and the other
  // still carries the ghost; guard both and their errors compound. The rainbow
  // streaking, the teal outlines, the iridescent speckle through foliage: none of
  // those are ghosts. They are what a sum produces when nothing bounds the sum.
  //
  // So the shippable paths never form that sum. They deliver one colour, taken whole.
  // Their only failure mode is ghosting, which is honest and bounded - it is the price
  // of showing an old frame, and it cannot turn into a colour that was never in the
  // scene.
  //
  // preset 1 = Standard, 2 = Extra temporal, 3 = Held frame.
  //
  // ============================ HELD FRAME ==========================================
  // Nothing here is gated. No trust falloff, no colour clip, no divergence test, no
  // history ceiling. A model frame shows the model's picture; a skipped frame shows the
  // previous one, reprojected, whole. Two pictures of the same kind, and NO per-pixel
  // decision anywhere that could come out differently on one frame type than the other.
  //
  // That is the entire point, and it is not a guess. The author of dlss5-neural-amd hit
  // the same wall from the other side and wrote down what it cost:
  //
  //   "ON A SKIPPED FRAME. You see the previous network output, a whole picture, which
  //    reads as a held frame rather than as a trail. It is deliberately not gated on
  //    freshness: gating it would flicker between two different pictures instead."
  //
  // Every guard added to this file over the past days is a gate, and each one is a
  // per-pixel decision that can land differently on a model frame than on a filled one.
  // A decision that flips at the cadence IS the flicker - so the guards were not failing
  // to stop it, they were producing it. Standard below still has them and is kept for
  // comparison, because being able to switch between the two is the only way to tell
  // which artefact a given scene actually suffers from.
  //
  // What this costs is honest and bounded: a moving object shows its old position for one
  // frame. That is ghosting, and it cannot become a colour that was not in the scene, and
  // it cannot pulse.
  // ========================= RESIDUAL TEMPORAL =====================================
  // Every path above this line reprojects a PICTURE. This one reprojects the model's EDIT
  // and leaves the picture alone, and that single change is the difference between showing
  // a stale frame and showing a stale correction.
  //
  //   model frame:   residual = cur - base, stored; out = base + residual, which IS cur
  //   skipped frame: the model did not run, so `cur` and `base` are the same un-denoised
  //                  frame and this frame's own residual is zero. Out = base + the PREVIOUS
  //                  residual, carried here by the motion vectors.
  //
  // So on a skipped frame the geometry on screen is THIS frame's - fresh, full detail,
  // nothing about the picture is old. Only the model's edit is a frame behind, and an edit
  // is a few percent of the picture rather than all of it. A reprojection error in a stale
  // picture moves a whole object; the same error in a stale edit moves a few percent of a
  // few percent. That is why this can be wrong and still not look wrong, and it is the
  // reason to expect more from it than from Held frame.
  //
  // dlss5-neural-amd measured the failure this is shaped to avoid: with frames skipped,
  // "the correction being pasted on belonged to a picture that had already moved", and it
  // left a heavy trail. Theirs was pasted WHERE IT WAS. This one is carried to where it
  // belongs first. Same idea, opposite result, and the difference is one reprojection.
  // ============================ GUIDED FILL (preset 5) ==============================
  // Every preset above reprojects a PICTURE and then argues with it: depth, divergence,
  // reactive mask, colour bound - each a guard deciding whether the old picture may be
  // shown here. Every one of those guards was born from a ghost and every one produced
  // a flicker, because a guard is a per-pixel decision and a decision can land differently
  // on a model frame than on a filled one. The two artefacts are the same bug seen from
  // two sides, and no amount of guarding resolves it, because the premise - "show the old
  // picture unless proven wrong" - is what needs proving on every pixel every frame.
  //
  // This preset never shows the old picture. Its rule: THE HISTORY DECIDES WEIGHTS, THE
  // CURRENT FRAME SUPPLIES VALUES. A filled frame is a joint bilateral filter of this
  // frame's un-denoised colour, where the weight of each neighbour comes from how similar
  // it looks in the reprojected denoised history (the guide). Where the reprojection is
  // right, the guide has the model's clean edges and flat regions, so the filter averages
  // grain away within surfaces and keeps edges - it looks denoised. Where the reprojection
  // is WRONG - a ghost, in every other preset - the guide's edges are in the wrong place,
  // so the filter averages the wrong neighbours together. But those neighbours are all
  // pixels of THIS frame, so the output is still a colour that exists here now: the ghost
  // cannot appear, because no colour of the old picture is ever copied. The worst a wrong
  // guide can do is smooth in a slightly wrong direction for one frame.
  //
  // What keeps this from flickering is that the MODEL FRAME RUNS THE SAME OPERATOR. On a
  // model frame the guide is the model's own output and the values are the raw frame it
  // was handed; the filter's answer is what a denoise alone would have produced, and the
  // difference between that and the model's output - `edit` - is what the model did beyond
  // denoising: tone, structure, its re-rendering. That edit is stored. On a filled frame
  // the edit is carried by the motion vectors and added back, bounded like every residual
  // here. So both frame types are `filter(raw) + edit`: the same kind of image, built the
  // same way, and what differs between them is only the guide's sub-pixel alignment and
  // the edit's age. Residual temporal (preset 4) tried to carry the whole residual and
  // failed because the residual is mostly the NOISE the model removed, which belongs to
  // one frame only; carrying it doubled the grain. Here the noise is removed spatially,
  // fresh, on both frame types, and only the part that is not noise travels.
  //
  // Cost: 49 taps of history and raw per pixel at model working size. Trivial next to
  // the model. The guide is sampled with the centre pixel's motion vector for the whole
  // window - a per-tap vector would cost 49 more loads and only matters at motion
  // boundaries, where it would shift weights, never colours.
  if (extraTemporal > 4.5 && extraTemporal < 5.5)
  {
   float3 baseLin = base.Load(int3(p,0)).rgb;
   if (!all(isfinite(baseLin))) baseLin = c.rgb;
   float2 wh = float2(float(w), float(h));
   // Spatial sigma 1.6 px over a 7x7 window; range sigma 0.045 in tonemapped units,
   // which is roughly a 7% step at mid-grey - texture above that keeps its edges, grain
   // below it is averaged. Measured on the guide, which is denoised, so grain never
   // reaches the weights and the weights cannot jitter with it.
   const float sigmaS2 = 2.0 * 1.6 * 1.6;
   const float sigmaR2 = 2.0 * 0.045 * 0.045;
   const bool onModel = modelFrame > 0.0;
   // THE GUIDE IS READ AT WHOLE TEXELS, NEVER BILINEARLY. The first version sampled the
   // history at `pv + (i,j)` with the bilinear sampler, and under any motion `pv` is
   // fractional, so every guide sample was a 2x2 blend - a low-pass on the one image whose
   // edges decide the weights. Softer guide, softer weights, softer filled frame; the
   // model frame's guide (its own output, read by Load) was never blurred. So filled
   // frames were systematically softer than model frames wherever anything moved, and
   // identical where nothing did - which is exactly the report from The Last of Us:
   // clean at rest, "flicker" the moment the camera turns. Snapping `pv` to the nearest
   // texel misplaces the weights by at most half a pixel, which moves no colour and
   // blurs nothing; a blurred guide blurs everything.
   int2 pvI = clamp(int2(floor(pv)), int2(0,0), mx);
   float3 gC = onModel ? tmap(c.rgb) : tmap(hist.Load(int3(pvI,0)).rgb);
   if (!all(isfinite(gC))) gC = tmap(baseLin);
   float3 acc = 0.0;
   float wsum = 0.0;
   [unroll] for (int j = -3; j <= 3; ++j)
   [unroll] for (int i = -3; i <= 3; ++i)
   {
    int2 q = clamp(p + int2(i, j), int2(0,0), mx);
    // Values: the raw frame, on both frame types (`base` is this frame's pre-model copy,
    // and on a filled frame it is the same picture as `cur`).
    float3 v = base.Load(int3(q,0)).rgb;
    float3 g = onModel ? tmap(cur.Load(int3(q,0)).rgb)
                       : tmap(hist.Load(int3(clamp(pvI + int2(i, j), int2(0,0), mx),0)).rgb);
    if (!all(isfinite(v)) || !all(isfinite(g))) continue;
    float3 dg = abs(g - gC);
    float d = max(dg.x, max(dg.y, dg.z));
    float wgt = exp(-float(i * i + j * j) / sigmaS2 - (d * d) / sigmaR2);
    acc += v * wgt;
    wsum += wgt;
   }
   float3 gf = wsum > 1e-6 ? acc / wsum : baseLin;
   // The geometric guards, computed once for both frame types. They act on the EDIT only:
   // a wrong guard costs the model's polish on a sliver for one frame, never a hole and
   // never a foreign colour. Ramps, never booleans.
   float dPrev = depthHist.SampleLevel(samp, pv / wh, 0).r;
   float occ = 0.0;
   if (isfinite(dPrev))
   {
    const float depthRel = 0.05;
    const float depthAbsFloor = 0.0015;
    float tol = max(max(max(dCur, dPrev) * depthRel, depthAbsFloor), depthSpread * 0.75);
    occ = saturate((abs(dCur - dPrev) - tol) / max(tol, 1e-6));
   }
   float keep = mvInsane ? 0.0 : (1.0 - occ) * (1.0 - mvDiverge) * (1.0 - reactiveAt(p));
   float3 prevEdit = sampleResid(pv);
   if (!all(isfinite(prevEdit))) { prevEdit = 0.0; keep = 0.0; }
   if (onModel)
   {
    // THE MODEL FRAME IS DAMPED AGAINST THE PREVIOUS MODEL FRAME, and this is what stops
    // lights, sky and signs from pulsing.
    //
    // The network re-decides every pixel on every call, and on emissive content its answer
    // moves between calls even when the scene does not. Two and three passes re-decide two
    // and three times and compound it; NR resolution above 100% hands the model a different
    // picture and it decides differently again. Under interleave that jitter lands at half
    // the frame rate, right where the eye is most sensitive, and reads as flicker on exactly
    // the content the report named: lights, sky, signs. No fill-frame logic can touch it,
    // because it is a difference between two MODEL frames.
    //
    // So the edit is averaged with the previous model frame's edit, carried here through the
    // filled frame by the motion vectors. This is Residual temporal's rule applied across the
    // cadence: both sides are the model's own output on the same kind of frame, so there is
    // no denoised-versus-raw asymmetry to alternate. Bounded the same way - the carried edit
    // may disagree with this frame's by as much again as this frame's own size, plus a small
    // floor - so a stale edit that landed on the wrong content cannot win against a fresh one.
    //
    // THIS IS THE 217be265 FORM, RESTORED BY THE USER'S CHOICE. A later build split the edit
    // into low and high bands and moved the high band around; side by side in Forza the user
    // judged this one the better picture and asked for it back. The band split is in the
    // handoff if it is ever wanted again.
    float3 editNow = c.rgb - gf;
    float3 dR = prevEdit - editNow;
    float dm = max(abs(dR.x), max(abs(dR.y), abs(dR.z)));
    float curM = max(abs(editNow.x), max(abs(editNow.y), abs(editNow.z)));
    float lim = curM + 0.05 * max(gf.x, max(gf.y, gf.z)) + 0.002;
    if (isfinite(dm) && dm > lim) prevEdit = editNow + dR * (lim / dm);
    float3 edit = lerp(editNow, prevEdit, saturate(alpha) * keep);
    residDst[p] = float4(edit, 0.0);
    dst[p] = float4(max(gf + edit, 0.0), c.a);
    return;
   }
   // Filled frame: the carried edit is the only thing that is not this frame's, so the
   // guards act on it alone. It is NOT clipped to the residual limit: that limit exists for
   // the residual composition below 100% NR resolution, and applying it here cut the model's
   // legitimately large edits - the very lift on a light or a sky that the model frame shows
   // in full - on filled frames only, which is a cadence flicker by construction. A loose
   // ceiling (four times the pixel's own brightness) remains as a sanity bound.
   float3 carried = fitResidual(gf, boundResidual(prevEdit * keep, gf, max(residualCap, 4.0)));
   residDst[p] = float4(carried, 0.0);
   dst[p] = float4(max(gf + carried, 0.0), c.a);
   return;
  }
  if (extraTemporal > 8.5)
  {
   // ==================== LMXXF: ONE-FRAME-LATE EDIT CARRY (preset 9) =====================
   // The lmxxf network answers a frame late, by design: it is launched when the frame that
   // fed it is submitted and never blocks the queue inside that frame. So what this pass has
   // at frame N is the model's EDIT of frame N-1 - its answer minus what it was fed - which
   // the host writes into residHist before this dispatch, in frame N-1's pixel space.
   //
   // Every frame then does exactly one thing: carry the edit to where it belongs now, by
   // this frame's motion and jitter, fade it where the geometry says the surface changed,
   // and add it to this frame's own raw colour. There is no frame type here and nothing
   // reprojects a PICTURE - only the edit, a few percent of the picture, which is the
   // Residual temporal rule (preset 4's skipped frame) applied to every frame alike.
   //
   // Two edits are carried. residHist (t7) is last frame's carried edit; `base` (t6) is the
   // model's FRESH edit when one arrived this frame (residualTemporal = 1), also in frame N-1's
   // space. The model re-decides brightness on every call, and shown raw that is the flicker;
   // so the fresh edit is averaged with the carried one, by `alpha` (Temporal stability), and
   // the carried one may not pull the fresh one further than the fresh one's own size - the
   // agreement clamp - which is what stops a stale edit trailing behind motion. With no fresh
   // edit (interleaving, or the model idle) the carried edit is carried once more; the host
   // drops it after a few silent frames.
   float3 baseLin = c.rgb;
   float dPrev = depthHist.SampleLevel(samp, pv / float2(w, h), 0).r;
   float occ = 0.0;
   if (isfinite(dPrev))
   {
    const float depthRel = 0.05;
    const float depthAbsFloor = 0.0015;
    float tol = max(max(max(dCur, dPrev) * depthRel, depthAbsFloor), depthSpread * 0.75);
    occ = saturate((abs(dCur - dPrev) - tol) / max(tol, 1e-6));
   }
   if (mvInsane) occ = 1.0;
   occ = max(occ, mvDiverge);
   // What the title marks as unpredictable from the previous frame - particles, transparents -
   // gets no edit either: both edits were made for a surface that is not there now.
   occ = max(occ, reactiveAt(p));
   float keep = 1.0 - occ;
   float3 prev = float3(0.0, 0.0, 0.0);
   if (keep > 0.0)
   {
    float3 r = sampleResid(pv);
    if (all(isfinite(r))) prev = r * keep;
   }
   float3 edit = prev;
   float stillW9 = 0.0;
   if (residualTemporal > 0.5 && keep > 0.0)
   {
    float3 fresh = float3(0.0, 0.0, 0.0);
    float3 fr = sampleBaseCR(pv);
    if (all(isfinite(fr))) fresh = fr * keep;
    float3 dR = prev - fresh;
    float dm = max(abs(dR.x), max(abs(dR.y), abs(dR.z)));
    float fm = max(abs(fresh.x), max(abs(fresh.y), abs(fresh.z)));
    float lim = fm + 0.05 * max(baseLin.x, max(baseLin.y, baseLin.z)) + 0.002;
    // #5: a still pixel may keep more of the carried edit against a fresh one that pulses (still-surface floor).
    [branch] if (staticRelax > 0.0 && !mvBad && isfinite(dPrev)) {
     stillW9 = saturate(staticRelax) * stillWeight(p, m, pv, dCur, dPrev, max(max(dCur, dPrev) * 0.05, 0.0015));
     lim = stillLimit(lim, dm, baseLin, stillW9);
    }
    if (isfinite(dm) && dm > lim) prev = fresh + dR * (lim / dm);
    edit = lerp(fresh, prev, saturate(alpha) * keep);
   }
   // Residual limit (0 = off) bounds the edit against the pixel it lands on; the result
   // leaves every channel non-negative.
   edit = fitResidual(baseLin, boundResidual(edit, baseLin, residualCap));
   residDst[p] = float4(edit, keep); // alpha: the reprojection validity, for the lmxxf stats line
   if (staticDebug > 0.5) { dst[p] = float4(float3(0.0, stillW9, 0.0) * 200.0, c.a); return; } // #5 overlay: green = relaxed
   if (debugView > 0.5) { dst[p] = float4(abs(edit) * 10.0, c.a); return; } // edit map
   dst[p] = float4(baseLin + edit, c.a);
   return;
  }
  if (extraTemporal > 3.5 && extraTemporal < 4.5)
  {
   float3 baseLin = base.Load(int3(p,0)).rgb;
   if (!all(isfinite(baseLin))) baseLin = c.rgb;

   if (modelFrame > 0.0)
   {
    // Self-contained: store what the model added, deliver what it produced.
    residDst[p] = float4(c.rgb - baseLin, 0.0);
    dst[p] = c;
    return;
   }

   // A skipped frame carries the previous edit forward. Geometry decides whether it may
   // be used - depth, never colour. A colour test answers differently on a model frame
   // than on a skipped one, and a test whose answer tracks the frame type IS the cadence.
   float3 carried = float3(0.0, 0.0, 0.0);
   float dPrev = depthHist.SampleLevel(samp, pv / float2(w, h), 0).r;
   // The same ramp as Held frame, for the same reason: a boolean reject draws the outline
   // of the region it rejected, and that outline is the artefact. Here it fades the
   // carried edit out instead of switching it off, so a disoccluded sliver loses the
   // model's polish gradually rather than at a line.
   float occ = 0.0;
   if (isfinite(dPrev))
   {
    const float depthRel = 0.05;
    const float depthAbsFloor = 0.0015;
    float tol = max(max(max(dCur, dPrev) * depthRel, depthAbsFloor), depthSpread * 0.75);
    occ = saturate((abs(dCur - dPrev) - tol) / max(tol, 1e-6));
   }
   if (mvInsane) occ = 1.0;
   occ = max(occ, mvDiverge);
   if (occ < 1.0)
   {
    float3 r = residHist.SampleLevel(samp, pv / float2(w, h), 0).rgb;
    if (all(isfinite(r))) carried = r * (1.0 - occ);
   }
   // Where it cannot be carried the answer is ZERO edit, not a fallback picture. The
   // un-denoised frame is a complete and correct image on its own; losing the model's
   // polish on a disoccluded sliver for one frame is the smallest failure available here,
   // and unlike a fallback it cannot introduce anything that was not already on screen.
   carried = fitResidual(baseLin, boundResidual(carried, baseLin, residualCap));
   residDst[p] = float4(carried, 0.0);
   dst[p] = float4(baseLin + carried, c.a);
   return;
  }
  if (extraTemporal > 7.5)
  {
   // ============================ SELF-TUNING (preset 8) ==============================
   // The model frame is ground truth, and it arrives every other frame. So every fill
   // strategy this pass knows can be GRADED against it: on a model frame, compute what each
   // strategy would have shown for this frame from the same inputs a skipped frame gets,
   // measure its error against the model's actual picture, and keep a smoothed score per
   // 16x16 tile. On a skipped frame, blend the strategies by those scores. Nothing is decided
   // by a rule someone wrote: where the picture stands still the reprojected picture wins,
   // where a character moves the edit-carry or the position-free curve wins, and it changes
   // its mind within a few model frames when the scene changes. Three candidates:
   //   A  the previous output reprojected (Held), exact when nothing moves
   //   B  this frame's raw + the carried edit (same-surface gated to the curve) + sharpening
   //   C  this frame's raw + the luminance curve + sharpening, position-free
   float2 resF = float2(float(w), float(h));
   const bool isModel = modelFrame > 0.0;
   float3 rawLin = isModel ? base.Load(int3(p,0)).rgb : c.rgb;
   if (!all(isfinite(rawLin))) rawLin = c.rgb;
   float3 rT = tmap(rawLin);
   float3 rMean, rSigma, rMin, rMax;
   if (isModel) stats3Base(p, mx, rMean, rSigma, rMin, rMax);
   else { rMean = mean; rSigma = sigma; rMin = nmin; rMax = nmax; }
   const float3 lumW = float3(0.2126, 0.7152, 0.0722);
   float3 A = tmap(hcolI);
   if (!all(isfinite(A))) A = rT;
   float3 lutT = lutAvail > 0.5 ? tmap(toneFallback(rawLin)) - rT : float3(0.0, 0.0, 0.0);
   if (!all(isfinite(lutT))) lutT = 0.0;
   float3 sharp = sharpGain * (rT - rMean);
   float3 C = rT + lutT + sharp;
   float3 carried = sampleResid(pv);
   if (!all(isfinite(carried))) carried = 0.0;
   float gateE = 0.0;
   {
    float hsE = histSigmaTm(pv, mx);
    float3 noiseE = sqrt(max(rSigma * rSigma - hsE * hsE, 0.0));
    float lumE = dot(rMean, lumW);
    float floorE = max(0.02 * min(lumE, 0.5) * 2.0, 0.002);
    float3 tolE = 4.2 * noiseE * (1.0 / 3.0) + floorE + 0.2 * (rMax - rMin);
    float3 rawPrevT = max(tmap(histMean3(pv, mx)) - carried, 0.0);
    float3 a2E = abs(rawPrevT - rMean) / tolE;
    float mE = max(a2E.x, max(a2E.y, a2E.z));
    gateE = isfinite(mE) ? 1.0 - saturate((mE - 1.0) * 2.0) : 0.0;
   }
   float occE = 0.0;
   {
    float dPrevE = depthHist.SampleLevel(samp, pv / resF, 0).r;
    if (isfinite(dPrevE))
    {
     float tolD = max(max(max(dCur, dPrevE) * 0.05, 0.0015), depthSpread * 0.75);
     occE = saturate((abs(dCur - dPrevE) - tolD) / max(tolD, 1e-6));
    }
   }
   if (mvBad) occE = 1.0;
   const float capE = min(residualCap, 0.15);
   float3 low = clamp(lerp(lutT, carried, gateE * (1.0 - occE)), -capE, capE);
   float3 B = rT + low + sharp;
   // The reprojected picture is never shown where the depth says this pixel was not
   // visible last frame: a disocclusion band is the one ghost no score can average away,
   // because it is a few pixels wide inside a tile that is otherwise still. Graded and
   // shown in the same gated form, so the score is a score of what is shown.
   A = lerp(C, A, 1.0 - occE);
   // PIXEL CLASS. Four cheap facts that predict whether reprojection can be trusted here:
   // how much this pixel's motion disagrees with its neighbours' (a silhouette, a joint),
   // how far it moved, whether the depth test fired, whether the same-surface test passed.
   uint fbin;
   {
    float mvLen = all(isfinite(m)) ? length(m) : 99.0;
    float div = 0.0;
    [unroll] for (int k = 0; k < 4; ++k)
    {
     int2 o = (k == 0) ? int2(-2, 0) : (k == 1) ? int2(2, 0) : (k == 2) ? int2(0, -2) : int2(0, 2);
     float2 mn = mv.Load(int3(clamp(p + o, int2(0,0), mx), 0)).xy * float2(mvScaleX, mvScaleY);
     if (all(isfinite(mn)) && all(isfinite(m))) div = max(div, length(mn - m));
    }
    uint bDiv = div < 0.25 ? 0u : div < 1.0 ? 1u : div < 3.0 ? 2u : 3u;
    uint bMv = mvLen < 0.5 ? 0u : mvLen < 2.0 ? 1u : mvLen < 6.0 ? 2u : 3u;
    uint bOcc = occE < 0.5 ? 0u : 1u;
    uint bGate = gateE < 0.5 ? 0u : 1u;
    fbin = bDiv * 16u + bMv * 4u + bOcc * 2u + bGate;
   }
   uint tx = (uint(w) + 15u) / 16u;
   uint2 tc = uint2(p) / 16u;
   uint tidx = (tc.y * tx + tc.x) * 16u;
   if (isModel)
   {
    // GRADE. Half the pixels (checkerboard) is plenty for a per-tile mean.
    float3 mT = tmap(c.rgb);
    if (((p.x ^ p.y) & 1) == 0)
    {
     // Error ABOVE THE GRAIN. A plain mean difference is mostly grain - the same for
     // every candidate, so it hid the thing that differs: a ghost band a few pixels wide
     // whose error is large but whose share of the tile is small. Subtracting the raw's
     // own local spread first leaves the structural error, and that is what is scored.
     float nf = 0.75 * dot(rSigma, lumW);
     float eA = max(dot(abs(A - mT), lumW) - nf, 0.0);
     float eB = max(dot(abs(B - mT), lumW) - nf, 0.0);
     float eC = max(dot(abs(C - mT), lumW) - nf, 0.0);
     if (isfinite(eA) && isfinite(eB) && isfinite(eC))
     {
      tileAcc.InterlockedAdd(tidx + 0u, uint(saturate(eA) * 4096.0));
      tileAcc.InterlockedAdd(tidx + 4u, uint(saturate(eB) * 4096.0));
      tileAcc.InterlockedAdd(tidx + 8u, uint(saturate(eC) * 4096.0));
      tileAcc.InterlockedAdd(tidx + 12u, 1u);
      if ((p.x & 2) == 0)
      {
       // A quarter of the pixels per class: 1024 fixed point keeps a 4K frame's worst
       // case inside 32 bits.
       uint fi = fbin * 16u;
       featAcc.InterlockedAdd(fi + 0u, uint(saturate(eA) * 1024.0));
       featAcc.InterlockedAdd(fi + 4u, uint(saturate(eB) * 1024.0));
       featAcc.InterlockedAdd(fi + 8u, uint(saturate(eC) * 1024.0));
       featAcc.InterlockedAdd(fi + 12u, 1u);
      }
     }
    }
    // Record the edit's low band and measure the sharpening (what Edit carry did).
    float3 cmn = 0.0; float3 bmn = 0.0;
    [unroll] for (int j = -1; j <= 1; ++j)
    [unroll] for (int i = -1; i <= 1; ++i)
    {
     int3 q = int3(clamp(p + int2(i, j), int2(0,0), mx), 0);
     cmn += tmap(cur.Load(q).rgb); bmn += tmap(base.Load(q).rgb);
    }
    cmn *= (1.0 / 9.0); bmn *= (1.0 / 9.0);
    float3 e = cmn - bmn;
    residDst[p] = float4(all(isfinite(e)) ? e : float3(0.0, 0.0, 0.0), 0.0);
    if (((p.x | p.y) & 1) == 0)
    {
     float hm = dot(abs(tmap(c.rgb) - cmn), float3(1.0, 1.0, 1.0) / 3.0);
     float hr = dot(abs(rT - bmn), float3(1.0, 1.0, 1.0) / 3.0);
     if (isfinite(hm) && isfinite(hr))
     {
      changeCount.InterlockedAdd(8, uint(saturate(hm) * 4096.0));
      changeCount.InterlockedAdd(12, uint(saturate(hr) * 4096.0));
     }
    }
    dst[p] = c;
    return;
   }
   // BLEND by the scores, read bilinearly across tiles so no tile edge is ever visible.
   float2 ft = (float2(p) + 0.5) / 16.0 - 0.5;
   int2 t0 = int2(floor(ft)); float2 f = ft - float2(t0);
   int2 tmax = int2(int(tx) - 1, int((uint(h) + 15u) / 16u) - 1);
   float4 s00 = tileScore[clamp(t0, int2(0,0), tmax)];
   float4 s10 = tileScore[clamp(t0 + int2(1,0), int2(0,0), tmax)];
   float4 s01 = tileScore[clamp(t0 + int2(0,1), int2(0,0), tmax)];
   float4 s11 = tileScore[clamp(t0 + int2(1,1), int2(0,0), tmax)];
   float3 sc = lerp(lerp(s00.xyz, s10.xyz, f.x), lerp(s01.xyz, s11.xyz, f.x), f.y);
   float trained = min(min(s00.w, s10.w), min(s01.w, s11.w));
   // Where this pixel is, plus what kind of pixel it is: two independent estimates of
   // each candidate's error, summed.
   float4 fsc = featScore[uint2(fbin, 0u)];
   if (fsc.w > 0.5 && all(isfinite(fsc.xyz))) sc += fsc.xyz;
   float3 wgt = float3(0.0, 1.0, 0.0); // untrained: edit carry
   if (trained > 0.5 && all(isfinite(sc)))
   {
    float smin = min(sc.x, min(sc.y, sc.z));
    wgt = exp(-4.0 * (sc - smin) / (smin + 0.001));
    if (!all(isfinite(wgt)) || dot(wgt, float3(1.0, 1.0, 1.0)) <= 0.0) wgt = float3(0.0, 1.0, 0.0);
   }
   wgt /= dot(wgt, float3(1.0, 1.0, 1.0));
   float3 outT = wgt.x * A + wgt.y * B + wgt.z * C;
   float3 outL = itmap(clamp(outT, 0.0, 0.995));
   // What is carried on is the model's edit as this frame received it, not the gated band
   // it showed: the next model frame grades candidate B from this history, and a grade of
   // a pre-gated, pre-clamped edit understated what B really carries - its ghost included.
   // Every reader gates and clamps at the point of use, so nothing accumulates.
   residDst[p] = float4(carried, 0.0);
   dst[p] = float4(max(outL, 0.0), c.a);
   return;
  }
  // Edit carry (preset 7) lived here. Removed: the Self-tuning preset above computes the
  // same fill as its candidate B and grades it against the model instead of assuming it.
  if (extraTemporal > 2.5)
  {
   // ============================ GUIDED FILL v2 (preset 6) ===========================
   // The Held picture (preset 3) with its one measured fault removed. On a Forza capture
   // (8 consecutive frames, 110% NR) the model's output on flat bright content - lamps,
   // signs, sky - was 0.5-0.58x the raw frame's brightness: the network compresses
   // highlights, and more so with more passes and more NR resolution. Held frame's
   // ghost bound then compares the reprojected MODEL picture against the current RAW
   // frame's 3x3 box, and on 89% of flat bright pixels the model value sat outside it,
   // so those pixels were handed back to the raw frame on filled frames only: model
   // frame dark lamp, filled frame bright lamp, at the cadence. That is the pulse the
   // reports describe, and every other fallback here (depth, divergence, reactive,
   // insane vectors) hands out the same raw-bright pixel when it fires.
   //
   // Two changes, both on the filled frame only; the model frame is `c`, untouched:
   //  1. The bound compares RAW against RAW. The model frame records its edit (output
   //     minus the 3x3 mean of the raw it was given); the filled frame subtracts the
   //     reprojected edit from the reprojected model picture, which leaves the previous
   //     raw, and tests THAT against the current raw box. Same surface: passes, the
   //     model's dark lamp is kept. Different surface (a real ghost): fails, as before.
   //  2. Every fallback wears the model's TONE (the LUT, toneFallback): where any guard
   //     hands a pixel to the current frame, that pixel is the raw frame (blurred where it
   //     is flat, bilateral-denoised where it is detailed) at the model's per-luminance
   //     brightness, measured on the last model frame. The carried tonal edit (3x3 means of
   //     both sides, no high band) is used by the raw-vs-raw test only - it is subtracted
   //     from the reprojected model picture to recover the previous raw - and is NOT added
   //     to the fallback. (Corrected 2026-09-26: this note and the log line used to say the
   //     fallback carried the edit; the code never did. The code is unchanged.)
   // Preset 3 below is byte-for-byte the `53d42bc0` path; `v2` is false there.
   const bool v2 = extraTemporal > 5.5;
   // A MODEL frame writes `c` straight through. It used to be itmap(tmap(c.rgb)),
   // which is a round trip through a tonemap that saturates at this game's scene
   // values - a pointless loss of precision on the one frame that has the right
   // answer already.
   if (modelFrame > 0.0)
   {
    if (v2)
    {
     // THE TONAL EDIT ONLY: the 3x3 mean of the model's output minus the 3x3 mean of the
     // raw it was given. The first form of v2 recorded `c - mean(raw)`, which carries the
     // model's edges and fine detail; reprojected a fraction of a pixel off and laid on
     // the current frame's own edges, that doubled every edge wherever a fallback fired -
     // the "strange, ugly" picture the user reported. The rule from the two-band Guided
     // fill work applies here as well: never carry a reprojected high band onto a frame
     // that has its own. With both sides blurred the edit is the model's brightness
     // decision alone; the fallback keeps the current frame's structure and takes only
     // the model's tone, which is all the pulse fix needed.
     float3 bm = 0.0; float3 cm = 0.0; float bn = 0.0;
     [unroll] for (int j = -1; j <= 1; ++j)
     [unroll] for (int i = -1; i <= 1; ++i)
     {
      int3 q = int3(clamp(p + int2(i, j), int2(0,0), mx), 0);
      float3 b = base.Load(q).rgb;
      float3 m = cur.Load(q).rgb;
      if (all(isfinite(b)) && all(isfinite(m))) { bm += b; cm += m; bn += 1.0; }
     }
     bm = bn > 0.0 ? bm / bn : c.rgb;
     cm = bn > 0.0 ? cm / bn : c.rgb;
     residDst[p] = float4(cm - bm, 0.0);
    }
    dst[p] = c; return;
   }

   // DEPTH DISOCCLUSION, and this is the only test here. It is what the torn block
   // behind the car was: with nothing rejected at all, a road pixel that reprojects
   // onto where the CAR used to be gets car colour, held sharply, frame after frame.
   // That is not the bounded ghosting this preset trades for - it is a hole in the
   // picture, and it has to be closed.
   //
   // But it is closed with GEOMETRY, never with colour, and that distinction is the
   // whole design. A colour test asks "do these two pictures agree?", and on a model
   // frame the current picture is denoised while on a skipped frame it is not - so the
   // answer changes with the frame type, and a test whose answer changes with the frame
   // type IS the cadence flicker. Depth does not care whether the model ran. It reports
   // the same surface on both frame types, so rejecting on it cannot produce a pulse.
   //
   // This is the depth reject that was removed from this path early on, brought back
   // knowing why it belongs: not as one more guard among the colour guards, but as the
   // only kind of guard that is safe here.
   float dPrev = depthHist.SampleLevel(samp, pv / float2(w, h), 0).r;
   float occ = 0.0;
   if (isfinite(dPrev))
   {
    const float depthRel = 0.05;         // 5% relative NDC change = a different surface
    const float depthAbsFloor = 0.0015;  // NDC jitter floor regardless of magnitude
    float tol = max(max(max(dCur, dPrev) * depthRel, depthAbsFloor), depthSpread * 0.75);
    // A RAMP, not a boolean. The hard version drew a visible patch with a clean edge on
    // the road behind the car - the boundary of the rejected region, which is exactly
    // where disocclusion happens when something moves. A binary test cannot help but
    // draw its own outline; widening the decision over a band means the two sources meet
    // gradually and no line exists to be seen.
    occ = saturate((abs(dCur - dPrev) - tol) / max(tol, 1e-6));
   }
   // And what it falls back TO is the other half of the fix, and the larger half.
   //
   // It used to be `c.rgb` - the raw frame, un-denoised, because the model did not run
   // this frame. Sitting that next to reprojected DENOISED history puts two pictures of
   // different character side by side, and the eye reads the difference as a patch of
   // mottled texture rather than as noise. That is what the blotchy wedge on the road
   // was: not a wrong colour, a wrong KIND of image.
   //
   // A 3x3 average of the current frame is not a denoise, but it removes most of what
   // separates the two - the per-pixel noise - so the fallback and its surroundings look
   // like the same picture. It costs some sharpness on a sliver of disoccluded pixels
   // for one frame, which is invisible next to a patch with an outline.
   float3 fallback = itmap(softCurTm(p, mx));
   // AND BLUR ONLY WHERE BLURRING IS INVISIBLE.
   //
   // The 3x3 average above exists so a rejected pixel does not sit next to denoised history
   // looking like a different KIND of image - it removes the per-pixel grain that separates
   // them. That reasoning holds on a road and inverts on hair: there the blur is not hiding
   // grain, it is destroying the strands, and since rejection only happens on filled frames
   // the hair ends up alternating sharp/soft at the cadence. That is the flicker reported on
   // hair, and it is the fallback's fault rather than the test's.
   //
   // sigma says which case this is. Flat neighbourhood - grain dominates, blur it. Detailed
   // neighbourhood - the detail dominates and the grain is the smaller error, so hand back
   // the frame as it is. Sharp-but-noisy is much closer to the model's output than
   // smooth-but-smeared, because the model keeps the strands too.
   // v2 shares two measurements between the fallback and the change test below: the
   // denoised history's 3x3 sigma (real detail) and the raw's grain, which is what the raw's
   // sigma has in excess of it.
   float3 noiseV2 = 0.0;
   {
    // v2: judge detail on the DENOISED history, not on the raw frame - in a grainy title
    // the grain reads as detail and hands back a sharp, grainy patch on filled frames only.
    float hs = v2 ? histSigmaTm(pv, mx) : 0.0;
    noiseV2 = sqrt(max(sigma * sigma - hs * hs, 0.0));
    float detail = v2 ? saturate(hs * 10.0) : saturate(max(sigma.x, max(sigma.y, sigma.z)) * 10.0);
    // v2: THE DETAILED FALLBACK IS THE RAW DENOISED, NOT THE RAW. Handing back the raw
    // itself on textured content put a grainy frame next to a clean model frame at the
    // cadence - the shimmer on moving ground in Silent Hill 2 the moment the change test
    // became able to see the character. A 3x3 bilateral whose range is the grain estimate
    // averages what differs by grain and keeps what differs by more (strands, edges), so
    // where the test fails the filled frame is still the same KIND of image as the model's.
    float3 detailed = c.rgb;
    if (v2)
    {
     float3 cTm = tmap(c.rgb);
     float3 sum = 0.0; float3 wsum = 0.0;
     float3 inv = 1.0 / max(2.0 * noiseV2 * noiseV2, 1e-6);
     [unroll] for (int j=-1;j<=1;j++) [unroll] for (int i=-1;i<=1;i++) {
      float3 q = tmap(cur.Load(int3(clamp(p+int2(i,j), int2(0,0), mx),0)).rgb);
      float3 dq = q - cTm;
      float3 wq = exp(-dq * dq * inv);
      sum += q * wq; wsum += wq;
     }
     detailed = itmap(sum / max(wsum, 1e-6));
    }
    fallback = lerp(fallback, detailed, detail);
    // v2: every fallback wears the model's tone, measured on the last model frame, so a
    // patch handed to the raw frame is not a brighter patch (the model darkens).
    if (v2) fallback = toneFallback(fallback);
   }
   float3 eS = 0.0;
   float tRaw = 0.0;
   if (v2)
   {
    eS = sampleResid(pv);
    if (!all(isfinite(eS))) eS = 0.0;
    // RAW AGAINST RAW, NOISE-AWARE. The previous frame's raw as a 3x3 mean, reprojected:
    // the blurred history minus the tonal edit the model frame recorded (both are 3x3
    // means, so the model's own detail cancels). Tested against the current raw's 3x3
    // mean with a tolerance for what a MEAN of nine noisy samples can wander by: a third
    // of their sigma, not the full sigma. The first v2 used the raw pixel box (k sigma),
    // and in a title with a ray-traced, grainy raw frame - Silent Hill 2 - that box was
    // so wide that nothing ever failed it: a whole jacket held over the road passed as
    // "same surface", which is the ghost in the screenshot. Same k, on the quantity
    // actually compared. No slider: the tolerance already scales with the noise.
    float3 rawPrev = max(histMean3(pv, mx) - eS, 0.0);
    // THE TOLERANCE WAS BLIND ON THE CHARACTER. Three things were wrong with
    // `4.2 * sigma / 3 + 0.02`, and the SH2 captures of 2026-09-21 (165944, 170001: James
    // walking, camera following) measured all three: his jacket held the PREVIOUS model
    // frame's folds on every filled frame while the raw already showed the next pose.
    //  1. `sigma` is the raw's own 3x3 sigma, which on hair, folds and any texture is the
    //     texture's contrast, not the grain - so textured content got a tolerance as wide
    //     as itself. The grain is what the raw has IN EXCESS of the denoised history at
    //     the same place: sqrt(sigma^2 - histSigma^2). Texture cancels, grain stays.
    //  2. The 0.02 floor is a tonemapped-unit constant, and tonemapping is linear near
    //     black: on a jacket at 0.03 it was most of the signal. A floor that scales with
    //     the luminance (2% at mid grey, never below 0.002) is a floor in what the eye
    //     sees.
    //  3. What a tighter tolerance must still forgive: the raw is jittered, and a sub-pixel
    //     shift moves a 3x3 mean by up to about a fifth of the neighbourhood's range.
    //     That term is the neighbourhood's own range, so it is large only on texture.
    // The verdict also reaches full fallback at 1.5x the tolerance instead of 2x.
    float3 noise = noiseV2;
    float lumMean = dot(mean, float3(0.2126, 0.7152, 0.0722));
    float floorTm = max(0.02 * min(lumMean, 0.5) * 2.0, 0.002);
    float3 tol = 4.2 * noise * (1.0 / 3.0) + floorTm + 0.2 * (nmax - nmin);
    float3 a2 = abs(tmap(rawPrev) - mean) / tol;
    float ma2 = max(a2.x, max(a2.y, a2.z));
    tRaw = isfinite(ma2) ? saturate((ma2 - 1.0) * 2.0) : 0.0;
   }
   float3 held = lerp(hcolI, fallback, occ);
   // A BAD VECTOR IS NOT A DISOCCLUSION, and treating them the same was the new artefact.
   //
   // The blurred fallback exists to make a disoccluded SLIVER look like the denoised
   // picture around it. `mvBad` is a different thing entirely: the vector is longer than
   // this pass is willing to trust, which at speed is true for most of the road - about
   // 85 pixels at 1139 high, and forward motion passes that near the bottom of the frame
   // easily. Routing that through the same blur softens half the screen, which is how a
   // fix for a small patch turned into a large one.
   //
   // So an untrusted vector falls back to the CURRENT FRAME, sharp. It is the honest
   // answer there: the frame is complete and correct, it is merely not denoised, and a
   // slightly different texture character across a fast-moving road reads as far less
   // than that road being blurred.
   if (mvInsane) held = v2 ? toneFallback(c.rgb) : c.rgb;
   // The divergence takes the history out where it says the source was static, by the same
   // weight and toward the same fallback the depth reject uses - so the two guards agree on
   // what a rejected pixel looks like and neither draws an edge the other does not.
   held = lerp(held, fallback, mvDiverge);
   // REACTIVE: the engine's own answer, and it outranks every guess above it.
   //
   // Ghost bound was tried on this at full strength and did not remove it, which is the
   // result that matters: a ghost the neighbourhood clip cannot see is one whose whole
   // NEIGHBOURHOOD reprojected wrongly too - a region of smoke, a soft shadow, an alpha
   // sheet. There is no local evidence left to detect it with, because everything local
   // agrees. The only thing that still knows is the renderer, and it already told us.
   //
   // So where the title says a pixel is reactive, the held picture is not used for it. It
   // falls back to the same blurred current frame the other two guards fall back to, so a
   // reactive region and a disoccluded one look alike and no boundary between them can
   // draw itself. Where the mask is absent this is zero and nothing below changes.
   held = lerp(held, fallback, reactiveAt(p));
   // GHOST BOUND, and the reason this one belongs in a preset whose whole premise is that
   // nothing is gated.
   //
   // Everything above is geometric: it asks where a pixel came from. That catches ghosts
   // whose vectors are wrong or absent at an EDGE, which is what velocity dilation fixed.
   // It cannot catch the case in the report - a car ghosted across the smoke behind it.
   // Smoke is a particle pass; it usually writes no motion vectors at all, so an entire
   // region of it reprojects by the road's motion, lands where the car was, and comes back
   // holding the car. Every vector involved is finite, smooth, and agrees with its
   // neighbours, so no geometric test has anything to object to. The pixels are wrong and
   // the geometry says they are fine.
   //
   // What IS wrong about them is the colour: the history is carrying a colour that does not
   // occur anywhere around this pixel now. That is the definition of a ghost, and it is
   // what Playdead's clip-to-AABB tests - already used by the Standard preset above.
   //
   // The reason a colour test is safe HERE, when the note at the top of this preset says
   // colour tests are what produce cadence flicker, is that this one is not a decision. The
   // gates that flickered were binary: they picked history or fallback, and picked
   // differently on a denoised frame than on an un-denoised one, so the pick alternated
   // with the cadence. A clip is CONTINUOUS and it is the identity everywhere the history
   // already sits inside the neighbourhood - which is every ordinary pixel, denoised or
   // not. It moves a pixel only when that pixel is tens of times outside its surroundings,
   // and the model's own re-rendering never is. So there is no pixel whose result alternates
   // with the frame type; there are only ghost pixels, which stop being ghosts.
   //
   // It walks the colour back along the line toward the centre of the neighbourhood and
   // stops at the boundary - one scalar dividing the whole offset, so it cannot rotate hue
   // the way the per-channel clamp did.
   if (heldGhostBound > 0.0 || v2)
   {
    // THE BOX IS BUILT FROM THE NEIGHBOURHOOD'S VARIANCE, not from a fixed fraction of
    // its brightness - and that correction is why this is worth reading.
    //
    // The first version padded nmin..nmax by a fixed percentage. It worked on asphalt and
    // it flickered on texture, and the report was exactly that: "ghosting is reduced with
    // the slider maxed, but the textures are flickering a lot." Which follows. A detailed
    // surface legitimately disagrees with its own 3x3 by a lot - that disagreement IS the
    // detail, plus the grain of an un-denoised frame - so a tight fixed box clips ordinary
    // texture. And because this runs on filled frames only (a model frame returns `c`
    // untouched), whatever it clips appears on one frame type and not the other. A decision
    // that lands differently on the two frame types is the cadence flicker, which is the
    // one rule this file is built around. Claiming a continuous clip was exempt from it was
    // true at a wide setting and false at a tight one.
    //
    // Variance fixes it at the root instead of by retuning. sigma is already computed above
    // for the Standard preset: on flat asphalt it is near zero, so the box closes and a
    // ghost standing there is caught hard; on a detailed wall it is large, so the box opens
    // and the detail is never touched. The slider now scales how many sigma are allowed
    // rather than a percentage of brightness, so "tighter" means tighter *relative to what
    // this surface actually does* - which is the only meaning that can be safe everywhere.
    //
    // THE SLIDER NEVER REACHES 1 SIGMA. The first sigma version ran 6 -> 1, and at the top
    // of that range the report was "still flickers, and at 0 the flicker stops but the
    // ghost is back". It follows from the arithmetic of a 3x3: a legitimate one-pixel
    // detail - a specular dot, a wire, a hair strand - sits 2.83 sigma from its own
    // neighbourhood's mean (eight samples at a, one at b: the centre is 8/9 of the way out
    // and sigma is 0.31 of it), and a pixel on a clean edge sits at exactly 1 sigma. So any
    // k below 3 clips ordinary detail, and since this runs on filled frames only that
    // detail then alternates with the cadence. The floor is 3 for that reason: the
    // tightest setting is the tightest one that cannot touch a real pixel.
    float k = lerp(6.0, 3.0, saturate(heldGhostBound));
    // A floor in tonemapped units, so a perfectly uniform neighbourhood cannot collapse the
    // box onto its own mean and flatten the picture. nmin/nmax still bound it: the box is
    // never allowed to be wider than the colours actually present.
    //
    // THIS IS THE `53d42bc0` BOUND, EXACTLY, AND IT STAYS THAT WAY. Two later attempts to
    // stop the emissive pulse at 2-3 passes (a ratio-tolerant box, then damping the model
    // frame against clamped history) each changed the picture the user keeps as the
    // reference, and he asked for this back twice. Any future attempt at that pulse goes
    // behind an opt-in switch, never into this path.
    float3 sT = k * sigma + 0.03;
    float3 lo = max(mean - sT, nmin);
    float3 hi = min(mean + sT, nmax);
    float3 pC = 0.5 * (hi + lo);
    float3 e  = max(0.5 * (hi - lo), 1e-4);
    // Measured in box units: 1 is the boundary, 2 is twice the box. The stats are in the
    // tonemapped domain, so the held colour is compared there too.
    float3 a  = abs((tmap(held) - pC) / e);
    float ma  = max(a.x, max(a.y, a.z));
    // AND WHERE IT FIRES IT GOES TO THE SAME PLACE THE OTHER GUARDS GO, not to the edge of
    // the box. Clipping to the boundary lands a ghost k sigma off the mean on the ghost's
    // side - a fainter ghost, with a tint that is on the filled frame and not on the model
    // frame. `fallback` is what the depth reject, the divergence and the reactive mask
    // already hand a rejected pixel: the current frame, blurred where it is flat and sharp
    // where it is detailed, chosen so a rejected pixel looks like the denoised picture
    // around it. A ramp from the boundary to twice the box, so nothing switches at a line.
    // At exactly 0 this block does not run at all and Held frame is byte-identical to
    // what shipped before it existed.
    // The structure gate that briefly lived here (history 3x3 sigma against current 3x3
    // sigma, so a flat-against-flat tonal offset would not fire) is gone again: it also let
    // the flat INTERIOR of a real ghost through - a car body over asphalt is flat on both
    // sides - and the user, comparing against the build he kept (`53d42bc0`), saw that as
    // the picture getting worse. This is that build's bound, exactly.
    float t = isfinite(ma) ? saturate(ma - 1.0) : 0.0;
    // v2: the verdict is raw-vs-raw (computed above); the fallback already wears the model's tone.
    if (v2) t = tRaw;
    // ADAPTIVE INTERLEAVE, the measurement that matters: a fallback that REPLACED something
    // visibly different is what the eye would have seen as a ghost or a flicker. A fallback
    // that equals what it replaced - the reprojection was right and the test merely fired on
    // grain or jitter - cost nothing and must not count, or interleave never gets to
    // interleave. The first version counted the test firing and ran the model every frame in
    // normal play. 0.03 tonemapped is about 8/255 in the midtones.
    if (v2 && t > 0.5 && ((p.x | p.y) & 1) == 0) {
     float dv = abs(dot(tmap(held) - tmap(fallback), float3(0.2126, 0.7152, 0.0722)));
     if (dv > 0.03) changeCount.InterlockedAdd(0, 1u);
    }
    held = lerp(held, fallback, t);
   }
   // Carry the edit forward for a second filled frame (cadence 3); the model frame
   // that follows rewrites it.
   if (v2) residDst[p] = float4(eS, 0.0);
   dst[p] = float4(held, c.a);
   return;
  }
  if (extraTemporal < 1.5)
  {
   float3 outLin = hcolI;

   {
    // STANDARD - the bound. This is Playdead's clip-to-AABB (the Salvi/Karis variance
    // clipping every TAA is built on), and NOT the scale-toward-black it replaces.
    //
    // Both answer the same question - the history here is a colour that is not present
    // around this pixel - and they differ in WHERE they send it, which turns out to be
    // the whole thing. Scaling multiplies the colour by one number, so a stale taillight
    // standing on asphalt is pulled toward BLACK: hue intact, but what lands on the road
    // is a dark red residue rather than road. Those were the streaks that survived, and
    // chasing them by retuning the scale could never have worked, because a scale has no
    // way to reach the colour the road actually is. Clipping walks the history back along
    // the line toward the CENTRE of what the neighbourhood contains and stops at the
    // boundary, so the same pixel lands on the asphalt's own colour and leaves nothing.
    //
    // It is still one scalar - maUnit - dividing the whole offset vector, so it cannot
    // rotate hue. That is what separates it from the per-channel clamp tried early on,
    // which divided each channel by a different amount and painted teal outlines around
    // the taillights and rainbow speckle through the foliage.
    //
    // For the record, what the scale version got wrong beyond the choice of direction: it
    // carried a constant floor of 0.55, "never dim by more than 45%". A trail pixel sits
    // about fifty times above its neighbourhood, so the correct factor was 0.025 and
    // max(0.025, 0.55) handed back 0.55 - it dimmed a ghost by 45%, then wrote the still
    // twenty-seven-times-too-bright result into dst, which is the next frame's history,
    // so the trail was refreshed rather than decayed. The guard had been firing on exactly
    // the right pixels the whole time and was arithmetically unable to remove what it
    // found; every round of tuning spent on WHICH pixels it selects was aimed at the half
    // that was already working.
    float3 loLin = itmap(nmin);
    float3 hiLin = itmap(nmax);
    float3 pClip = 0.5 * (hiLin + loLin);
    // The box is never allowed to be narrower than +/-35% of its own centre, and that
    // padding is this guard's entire tolerance. A 3x3 taken on a flat surface - road, sky,
    // a wall - has nine samples that agree, so its true width is essentially zero, and an
    // unpadded clip would snap every such pixel to the local mean and flatten the picture.
    // The model's own re-rendering moves colours by well under a third and passes through
    // untouched; a taillight standing on grey asphalt is tens of times out and does not.
    float3 eClip = max(0.5 * (hiLin - loLin), abs(pClip) * 0.35 + 1e-4);
    float3 vClip = outLin - pClip;
    float3 aUnit = abs(vClip / eClip);
    float maUnit = max(aUnit.x, max(aUnit.y, aUnit.z));
    if (maUnit > 1.0)
     outLin = pClip + vClip / maUnit;
   }

   // Where the motion vector is not trustworthy there is no usable history, so the
   // current frame is the only honest answer. Blended, not switched, so the weight can
   // move without the pixel changing what kind of image it is.
   //
   // And a CEILING on that weight, which is what was missing and what the taillight
   // smear actually was.
   //
   // `trust` reaches 1 whenever a pixel did not move - and the thing that never moves in
   // screen space is the player's own car, including its lights. At weight 1 the pixel
   // takes its entire colour from the previous frame, whose colour came entirely from
   // the frame before that. Nothing fresh can ever enter, so nothing can overwrite a
   // smear once it is in there: it is a closed loop, and the streaks trailing the lights
   // were it. A temporal filter with weight 1 is not a filter, it is storage.
   //
   // On a MODEL frame `c` is the denoised picture, so letting 30% of it in every time
   // costs nothing and clears a stale trail within a few frames. On a SKIPPED frame `c`
   // is un-denoised, so only a little is admitted - enough to keep the loop open, which
   // is the whole point, without pulling in grain.
   const float histCapModel = 0.70;
   const float histCapFill  = 0.92;
   float histCap = modelFrame > 0.0 ? histCapModel : histCapFill;
   float3 curLin = itmap(tmap(c.rgb));
   dst[p] = float4(lerp(curLin, outLin, min(trust, histCap)), c.a);
   return;
  }

  // ---------------- EXTRA TEMPORAL: the experimental lane -------------------------
  // Left as it is, by request. This one does split the frame, which is what lets it be
  // sharper than the two above - and also why it is the one still being worked on.
  float3 loHist;
  float guardScale = 1.0;
  {
   // EXTRA TEMPORAL - the lane that is still being worked on.
   //
   // Where the reprojected history is a colour foreign to its surroundings, fall back
   // to what THIS frame says is at the pixel, not to a clamped version of the stale
   // value. That distinction is what the wispy trails behind the taillights exposed:
   // the glow is a screen-space effect stuck to a car that is still in screen space,
   // while the road it lies on is moving fast, so it gets dragged by the road's motion
   // vectors. Clamping that dragged colour into the neighbourhood box removed its red
   // and left a dark residue - the streaks - because a bounded wrong answer is still
   // a wrong answer. The current frame's own low band is the right content there; it
   // is un-denoised, but it is a blur, so its noise is already mostly averaged out.
   float3 hLin  = itmap(loHistRaw);
   float3 loLin = itmap(nmin);
   float3 hiLin = itmap(nmax);
   float3 clampedLin = clamp(hLin, loLin, hiLin);
   // One number, relative to the colour's own magnitude, so it means the same thing at
   // any scene brightness; and a dead zone, so the model's own lift in brightness and
   // saturation passes untouched and only a genuinely foreign colour is replaced.
   float excess = length(hLin - clampedLin) / max(length(hLin), 1e-3);
   float pull = saturate((excess - 0.10) / 0.30);
   loHist = lerp(loHistRaw, loCur, pull);
  }
  // -- Where the vector is not trusted, fall back ALONG THE SAME AXIS - toward the
  //    current frame's own low band. Both ends are low-frequency, so this weight
  //    can move freely without changing what kind of image the pixel is.
  float3 lowBand = lerp(loCur, loHist, trust);
  // -- Detail.
  //
  //    `sharpFill` picks between the two ways of getting it, because they fail in
  //    opposite directions and which one wins is a judgement about this game's picture
  //    rather than something derivable.
  //
  //    OFF - one formula on both frame types: scale the current frame's own detail.
  //    Symmetric, so it cannot produce a cadence, but the scale is a straight trade -
  //    low enough to hide the sensor grain on a skipped frame is also low enough to
  //    blur the model's clean detail on a model frame, where there was nothing to hide.
  //
  //    ON - take detail from whichever side is actually denoised: the current frame on
  //    a model frame, the reprojected history on a skipped one. Both are then full
  //    strength and clean, so neither is blurred and neither is grainy, and what
  //    differs between frame types is only the sub-pixel reprojection error.
  //
  //    This was tried once and made things worse, which is why it is a switch and not
  //    simply the new behaviour - but it was tried while the model was still being
  //    handed one frame of motion per call, so its internal history was misaligned and
  //    the history detail this depends on was corrupt at the source. That is fixed now
  //    (see Interleave.h), so the experiment is worth repeating on its own merits.
  //    Where the motion vector is not trustworthy it falls back to the scaled current
  //    detail, the same place the low band falls back to.
  float3 dCur = tmap(c.rgb) - loCur;
  float3 detail;
  if (sharpFill > 0.0)
  {
   // The history's own detail, used as it is. No bound, no noise subtraction.
   //
   // Both were tried, in that order, chasing a faint halo around moving edges, and both
   // cost more than the halo did:
   //   - bounding by 1.5*|dCur| clamps the three colour channels by different amounts,
   //     which IS a hue change, and it painted purple fringes on power lines and colour
   //     speckle through foliage. Bounding by magnitude instead fixed the hue but left
   //     the bound itself re-rolling at every pixel from the noise in `dCur`, which
   //     multiplied the history's detail by a random number - grey grain, from the
   //     guard rather than from the data.
   //   - subtracting `sigma` first, to make that bound use "real" detail, was worse
   //     still: `sigma` is the local spread of the 3x3, and on asphalt or foliage that
   //     spread is mostly real TEXTURE, not noise. Subtracting it deleted the texture.
   //     That was the softness.
   //
   // The halo they were chasing is a sub-pixel reprojection error, which is a real
   // limit of reprojecting anything, and it is smaller than either cure. Left alone.
   float3 dHist = tmap(hcolI) - loHistRaw;
   // `guardScale` is 1 unless the Standard guard pulled the history down, in which case
   // the detail is pulled by exactly the same single factor - so the two bands stay
   // consistent and the bound applies to the whole colour. One scalar on all three
   // channels, so this cannot shift hue any more than the low-band guard can.
   detail = modelFrame > 0.0 ? dCur : lerp(detailScale * dCur, dHist * guardScale, trust);
  }
  else
   detail = detailScale * dCur;
  // Diagnostic overlays. Each answers one question that a screenshot of the final
  // picture cannot, which is the point: this exists so the next change is aimed.
  //   1 trust      - white = took its picture from the reprojected history, black =
  //                  fell back to the un-denoised current frame. Grain and softness
  //                  both live wherever this is dark.
  //   2 frame type - red where the model ran, blue where it was skipped. Anything
  //                  visible in only one colour is locked to the cadence.
  //   3 clamp      - red where the neighbourhood clamp pulled the history back, i.e.
  //                  where the ghost guard is actually firing.
  if (debugView > 0.0 && debugView < 3.5)
  {
   float3 dbg;
   if (debugView < 1.5) dbg = float3(trust, trust, trust);
   else if (debugView < 2.5) dbg = modelFrame > 0.0 ? float3(1.0, 0.1, 0.1) : float3(0.1, 0.3, 1.0);
   else { float pulled = saturate(length(loHistRaw - loHist) * 20.0); dbg = float3(pulled, 1.0 - pulled, 0.0); }
   // Scaled to this pixel's own brightness before it is written. `dst` becomes next
   // frame's HISTORY, so writing a raw 0..1 debug colour into a scene whose values run
   // to four figures leaves the next frame comparing its history against nonsense - the
   // guard then rejects everything and the overlay reports a problem it created itself.
   // That is exactly how the first clamp-activity reading came out red edge to edge.
   // Scaling keeps the history in the right range, so what the overlay shows is the
   // pass's real behaviour rather than its own footprint.
   // A FIXED scale, not this pixel's brightness. Scaling by brightness kept the history
   // in range but modulated the overlay itself, which made the greyscale trust view
   // unreadable - dark scenery read as "no trust" and bright scenery as "full trust"
   // no matter what the value was. A constant in the scene's own order of magnitude
   // keeps the history sane AND leaves the overlay meaning only what it measures.
   dst[p] = float4(dbg * 200.0, c.a);
   return;
  }
  dst[p] = float4(itmap(lowBand + detail), c.a);
  dst[p] = float4(itmap(lowBand + detail), c.a);
  return;
 }
 // ========================= END MODEL INTERLEAVE =============================

 if (mvBad) m = 0.0;
 float2 prev = float2(p) + 0.5 + m + jit;
 if (prev.x<0.0 || prev.y<0.0 || prev.x>=float(w) || prev.y>=float(h)) { dst[p]=c; return; }
 // Depth-based disocclusion reject: the colour clamp only catches a reprojected
 // sample whose COLOUR looks wrong; it misses history landing on similarly
 // coloured but different geometry. A large relative depth change at the same
 // reprojected position means a different surface, so drop it outright.
 float dHist = depthHist.SampleLevel(samp, prev / float2(w, h), 0).r;
 if (isfinite(dHist)) {
  const float depthRel = 0.05;        // 5% relative NDC change
  const float depthAbsFloor = 0.0015; // NDC jitter floor regardless of value
  float depthTol = max(max(dCur, dHist) * depthRel, depthAbsFloor);
  if (abs(dCur - dHist) > depthTol) { dst[p] = c; return; }
 }
 float3 hcol = sampleHistory(prev);
 if (!all(isfinite(hcol))) { dst[p]=c; return; }
 // #5 still-surface steadiness: on a pixel that has not moved, the box is widened by a brightness-proportional floor,
 // so a flat surface pulsing in place is damped instead of passed through. lo <= mean <= hi, so a zero floor leaves the
 // box as it was, and staticRelax 0 (a uniform branch) is byte-identical.
 float stillW = 0.0;
 [branch] if (staticRelax > 0.0 && !mvBad && isfinite(dHist)) {
  stillW = saturate(staticRelax) * stillWeight(p, m, prev, dCur, dHist, max(max(dCur, dHist) * 0.05, 0.0015));
  float3 fS = stillFloorTm(mean, stillW);
  lo = min(lo, mean - fS); hi = max(hi, mean + fS);
 }
 if (mode == 1) {
  // Difference-gated smoothing (after lmxxf's native_output_smooth): blend toward
  // the reprojected history ONLY where it already matches the current frame (low
  // shimmer); real motion/edges differ and pass through. The history is FIRST
  // variance-clamped to the neighbourhood (like mode 0) so a small reprojection
  // error can never smear a value from outside the local range.
  float3 htmg = clamp(tmap(hcol), lo, hi);
  float3 ctmg = tmap(c.rgb);
  float dmax = max(max(abs(ctmg.x-htmg.x), abs(ctmg.y-htmg.y)), abs(ctmg.z-htmg.z));
  float wgate = alpha * saturate(1.0 - dmax / max(threshold, 1e-4));
  if (staticDebug > 0.5) { dst[p] = float4(float3(0.0, stillW, 0.0) * 200.0, c.a); return; } // #5 overlay
  dst[p] = float4(lerp(c.rgb, itmap(htmg), wgate), c.a);
  return;
 }
 float3 htm = tmap(hcol);
 float3 clippedTm = clamp(htm, lo, hi);
 // How far the history sat outside the valid box: large on moving edges /
 // disocclusions where reprojection is unreliable, so drop the history weight
 // there and take the fresh frame instead of smearing. The floor keeps a
 // low-variance neighbourhood (a light's glow, a flat wall, sky) from having a
 // tiny box explode the ratio and hard-flip the weight between 0 and alpha.
 float ghostFloor = length(sigma) * 2.0 + 0.02;
 float ghost = length(htm - clippedTm) / max(length(hi - lo), ghostFloor);
 float a2 = alpha * (1.0 - ghostReject * saturate(ghost));
 // #5 overlay: green = relaxed, red = relaxed but rejected as a real change (the ghost term).
 if (staticDebug > 0.5) { float rj = stillW * saturate(ghost); dst[p] = float4(float3(rj, stillW - rj, 0.0) * 200.0, c.a); return; }
 dst[p] = float4(lerp(c.rgb, itmap(clippedTm), a2), c.a);
#endif
}
)";
// TONE TRANSFER, PASS 1 (model frames): 64 bins of raw tonemapped luminance, each summing
// the model's tonemapped luminance (10-bit fixed point) and a count. Group-shared first,
// one global atomic per touched bin per group after.
// Edit accumulation (presets 10/11) takes a second form of the same measurement: bins of HALF A
// STOP of raw luminance (log2 L in [-14, +18]) and, per bin, the signed sum of log2(model / raw)
// in 1/64-stop fixed point. The tonemapped form cannot serve there: tm(x) = x/(1+x) puts every
// value past ~100 into its last bin, and a real Forza capture runs to four figures - one bin for
// the whole scene. The full constant block is declared so `extraTemporal` can pick the form;
// the root constants are the ones the main pass just set, same root signature.
inline constexpr char ToneAccumulateShader[] = R"(
Texture2D<float4> cur  : register(t0);
Texture2D<float4> base : register(t6);
RWByteAddressBuffer lutAccum : register(u4);
cbuffer P : register(b0) { uint w; uint h; float alpha; uint reset; float mvScaleX; float mvScaleY; float ghostReject; uint mode; float threshold; float interleaved; float detailScale; float modelFrame; float sharpFill; float debugView; float extraTemporal; float residualTemporal; float residualCap; float depthInv; float heldGhostBound; float reactiveAvail; float lutAvail; float jitterDx; float jitterDy; float sharpGain; }
groupshared uint gS[64];
groupshared uint gC[64];
groupshared uint gD[64];
groupshared uint gE[64];
[numthreads(8,8,1)] void main(uint3 tid : SV_DispatchThreadID, uint gi : SV_GroupIndex) {
 gS[gi] = 0u; gC[gi] = 0u; gD[gi] = 0u; gE[gi] = 0u;
 GroupMemoryBarrierWithGroupSync();
 // Every other pixel in each axis: a quarter of the frame is plenty for 64 bins, and it
 // keeps a 4K frame's per-bin sum inside 32 bits at 10-bit fixed point. The host launches
 // one thread per SAMPLE (half the width, half the height) - it launched one per pixel and
 // three in four of them only returned, measured at about 0.06 ms of the pass at 2560x1440.
 const uint2 q2 = tid.xy * 2u;
 bool inside = q2.x < w && q2.y < h;
 if (inside) {
  int2 p = int2(q2);
  int2 mx = int2(int(w) - 1, int(h) - 1);
  float3 m = 0.0; float3 b = 0.0; float n = 0.0;
  float3 cm0 = 0.0, cb0 = 0.0;
  [unroll] for (int j = -1; j <= 1; ++j) [unroll] for (int i = -1; i <= 1; ++i) {
   int3 q = int3(clamp(p + int2(i, j), int2(0, 0), mx), 0);
   float3 cm = cur.Load(q).rgb; float3 cb = base.Load(q).rgb;
   if (i == 0 && j == 0) { cm0 = cm; cb0 = cb; }
   if (all(isfinite(cm)) && all(isfinite(cb))) { m += cm; b += cb; n += 1.0; }
  }
  if (n > 0.0) {
   m /= n; b /= n;
   if (extraTemporal > 9.5) {
    // Edit accumulation. danielblnc: t0 = the model's answer, t6 = the raw it was handed.
    // lmxxf: t0 = this frame's raw, t6 = the model's edit of frame N-1 - unwarped, which is
    // harmless here: this is a per-luminance statistic over a quarter of the frame, not a
    // per-pixel answer, and a one-frame shift of an edit moves almost no pixel between bins.
    const float3 rawM = extraTemporal > 10.5 ? m : b;
    const float3 modM = extraTemporal > 10.5 ? m + b : m;
    const float lb = dot(rawM, float3(0.2126,0.7152,0.0722)), lm = dot(modM, float3(0.2126,0.7152,0.0722));
    if (isfinite(lb) && isfinite(lm) && lb > 1e-7 && lm > 1e-9) {
     const uint bin = uint(clamp(round((log2(lb) + 14.0) * 2.0), 0.0, 63.0));
     const int qv = int(round(clamp(log2(lm / lb), -4.0, 4.0) * 64.0));
     InterlockedAdd(gS[bin], asuint(qv)); InterlockedAdd(gC[bin], 1u);   // signed sum in uint wraps correctly
     // danielblnc only: how much local detail the model leaves at this brightness - its pixel's
     // distance from its own 3x3 mean against the raw's, both over the raw mean, in 1/1024 and
     // capped at 1 (a 4K frame's quarter then still fits 32 bits in one bin). The prior of Edit
     // accumulation scales this frame's own detail by the ratio, so where the carry is refused
     // the picture keeps the model's texture amount instead of the raw's: less grain where the
     // model denoises, more crispness where it sharpens (Silent Hill 2 measured 0.95x, 1.55x with
     // the proxy; Forza 1.05x). lmxxf's answer here is a frame late and unwarped: a gain survives
     // that, a pixel's detail does not (it would measure two frames' grain), so lmxxf skips it.
     if (extraTemporal < 10.5) {
      const float3 lw = float3(0.2126,0.7152,0.0722);
      const float dR = abs(dot(cb0, lw) - lb), dM = abs(dot(cm0, lw) - lm);
      if (isfinite(dR) && isfinite(dM)) {
       InterlockedAdd(gD[bin], uint(saturate(dM / lb) * 1024.0 + 0.5));
       InterlockedAdd(gE[bin], uint(saturate(dR / lb) * 1024.0 + 0.5));
      }
     }
    }
   } else {
   float lb = max(dot(b, float3(0.2126, 0.7152, 0.0722)), 0.0);
   float lm = max(dot(m, float3(0.2126, 0.7152, 0.0722)), 0.0);
   float tb = lb / (1.0 + lb); float tm = lm / (1.0 + lm);
   if (isfinite(tb) && isfinite(tm)) {
    uint bin = min(uint(saturate(tb) * 64.0), 63u);
    InterlockedAdd(gS[bin], uint(saturate(tm) * 1024.0 + 0.5));
    InterlockedAdd(gC[bin], 1u);
   }
   }
  }
 }
 GroupMemoryBarrierWithGroupSync();
 if (gC[gi] > 0u) {
  lutAccum.InterlockedAdd(gi * 4, gS[gi]);
  lutAccum.InterlockedAdd(256 + gi * 4, gC[gi]);
  if (gE[gi] > 0u) {
   lutAccum.InterlockedAdd(512 + gi * 4, gD[gi]);
   lutAccum.InterlockedAdd(768 + gi * 4, gE[gi]);
  }
 }
}
)";
// TONE TRANSFER, PASS 2 (one group of 64): the ratio per bin, count-weighted over the
// bin and its neighbours so the curve is smooth and an empty bin borrows from the ones
// beside it; then the accumulator is zeroed for the next model frame.
// Edit accumulation (presets 10/11) resolves the log form instead, into floats [64..191], and
// runs EVERY frame, not only on model frames: on a frame with nothing accumulated the sums are
// zero, the target [128..191] is kept, and the shown curve [64..127] only glides toward it -
// by sqrt(Temporal stability) per frame, which at cadence 2 is Temporal stability per model
// interval, the same damping the carried state gets. So a new answer never steps the curve.
// The mean log-ratio per bin needs no bin centre (the tonemapped form divided by one, which
// biased every bin toward its middle) and has no 0.995 clip.
// It resolves the danielblnc detail ratio beside it, into floats [192..319] (see ToneAccumulate).
inline constexpr char ToneLutShader[] = R"(
RWByteAddressBuffer lutAccum : register(u4);
RWByteAddressBuffer lutOut   : register(u5);
cbuffer P : register(b0) { uint w; uint h; float alpha; uint reset; float mvScaleX; float mvScaleY; float ghostReject; uint mode; float threshold; float interleaved; float detailScale; float modelFrame; float sharpFill; float debugView; float extraTemporal; float residualTemporal; float residualCap; float depthInv; float heldGhostBound; float reactiveAvail; float lutAvail; float jitterDx; float jitterDy; float sharpGain; }
[numthreads(64,1,1)] void main(uint3 tid : SV_DispatchThreadID) {
 uint i = tid.x;
 if (extraTemporal > 9.5) {
  float s = 0.0, n = 0.0;
  [unroll] for (int k = -2; k <= 2; ++k) { int j = clamp(int(i)+k, 0, 63); float wgt = k==0 ? 3.0 : (abs(k)==1 ? 2.0 : 1.0);
    s += wgt * float(asint(lutAccum.Load(uint(j)*4))); n += wgt * float(lutAccum.Load(256 + uint(j)*4)); }
  const float Rold = asfloat(lutOut.Load((128 + i) * 4)), Sold = asfloat(lutOut.Load((64 + i) * 4));
  const bool had = lutAvail > 0.5 && isfinite(Rold) && Rold > 0.0 && isfinite(Sold) && Sold > 0.0;
  float Rt = had ? Rold : 1.0;
  if (n >= 32.0) Rt = exp2(clamp(s / (n * 64.0), -4.0, 4.0));     // mean log-ratio per bin (no bin-centre bias, no clip)
  const float St = had ? lerp(Rt, Sold, sqrt(saturate(alpha))) : Rt; // per-frame glide = Temporal stability per model interval at cadence 2
  lutOut.Store((64 + i) * 4, asuint(St)); lutOut.Store((128 + i) * 4, asuint(Rt));
  // The model's detail ratio per bin (danielblnc; floats [192..255] shown, [256..319] target), the
  // same smoothing and the same glide. A bin needs 32 samples and a raw that has detail at all -
  // a mean of 0.2% of its brightness - before the ratio means anything; otherwise the last one
  // stays (1 before any). lmxxf never accumulates it, so its bins stay at 1.
  float sd = 0.0, se = 0.0;
  [unroll] for (int kd = -2; kd <= 2; ++kd) { int j = clamp(int(i)+kd, 0, 63); float wgt = kd==0 ? 3.0 : (abs(kd)==1 ? 2.0 : 1.0);
    sd += wgt * float(lutAccum.Load(512 + uint(j)*4)); se += wgt * float(lutAccum.Load(768 + uint(j)*4)); }
  const float Dold = asfloat(lutOut.Load((256 + i) * 4)), DSold = asfloat(lutOut.Load((192 + i) * 4));
  const bool hadD = lutAvail > 0.5 && isfinite(Dold) && Dold > 0.0 && isfinite(DSold) && DSold > 0.0;
  float Dt = hadD ? Dold : 1.0;
  if (n >= 32.0 && se >= 2.0 * n) Dt = clamp(sd / se, 0.25, 4.0);
  const float DSt = hadD ? lerp(Dt, DSold, sqrt(saturate(alpha))) : Dt;
  lutOut.Store((192 + i) * 4, asuint(DSt)); lutOut.Store((256 + i) * 4, asuint(Dt));
 } else {
 float s = 0.0; float n = 0.0;
 [unroll] for (int k = -2; k <= 2; ++k) {
  int j = clamp(int(i) + k, 0, 63);
  float wgt = (k == 0) ? 3.0 : ((abs(k) == 1) ? 2.0 : 1.0);
  s += wgt * float(lutAccum.Load(uint(j) * 4));
  n += wgt * float(lutAccum.Load(256 + uint(j) * 4));
 }
 float centre = (float(i) + 0.5) / 64.0;
 float r = 1.0;
 if (n >= 32.0) {
  float tm = (s / n) / 1024.0;
  r = clamp(tm / centre, 0.25, 2.0);
 }
 lutOut.Store(i * 4, asuint(r));
 }
 GroupMemoryBarrierWithGroupSync();
 lutAccum.Store(i * 4, 0u);
 lutAccum.Store(256 + i * 4, 0u);
 lutAccum.Store(512 + i * 4, 0u);
 lutAccum.Store(768 + i * 4, 0u);
}
)";
// Self-tuning interleave (preset 8), the learning half: once per model frame, one thread per
// 16x16 tile turns the accumulated candidate errors into a smoothed score per candidate.
inline constexpr char TileScoreShader[] = R"(
cbuffer P : register(b0) { uint w; uint h; float alpha; uint reset; float mvScaleX; float mvScaleY; float ghostReject; uint mode; float threshold; float interleaved; float detailScale; float modelFrame; float sharpFill; float debugView; float extraTemporal; float residualTemporal; float residualCap; float depthInv; float heldGhostBound; float reactiveAvail; float lutAvail; float jitterDx; float jitterDy; float sharpGain; }
RWByteAddressBuffer tileAcc : register(u7);
RWTexture2D<float4> tileScore : register(u8);
RWByteAddressBuffer featAcc : register(u9);
RWTexture2D<float4> featScore : register(u10);
RWByteAddressBuffer changeCount : register(u6);
[numthreads(8,8,1)] void main(uint3 tid : SV_DispatchThreadID) {
 uint tx = (w + 15u) / 16u; uint ty = (h + 15u) / 16u;
 if (tid.y == 0u && tid.x < 64u) {
  // The 64 pixel classes, folded by the first row of threads (the host dispatches at
  // least 64 in x). A class needs 32 samples before it says anything.
  uint fi = tid.x * 16u;
  if (reset != 0u) { featScore[uint2(tid.x, 0u)] = float4(0.0, 0.0, 0.0, 0.0); featAcc.Store4(fi, uint4(0u, 0u, 0u, 0u)); }
  else {
   uint4 fs = featAcc.Load4(fi);
   featAcc.Store4(fi, uint4(0u, 0u, 0u, 0u));
   if (fs.w >= 32u) {
    float3 me = float3(fs.xyz) / (float(fs.w) * 1024.0);
    float4 pf = featScore[uint2(tid.x, 0u)];
    float3 fsc = (pf.w > 0.5 && all(isfinite(pf.xyz))) ? lerp(pf.xyz, me, 0.25) : me;
    featScore[uint2(tid.x, 0u)] = float4(fsc, 1.0);
   }
  }
 }
 if (tid.x >= tx || tid.y >= ty) return;
 uint idx = (tid.y * tx + tid.x) * 16u;
 if (reset != 0u) { tileScore[tid.xy] = float4(0.0, 0.0, 0.0, 0.0); tileAcc.Store4(idx, uint4(0u, 0u, 0u, 0u)); return; }
 uint4 s = tileAcc.Load4(idx);
 tileAcc.Store4(idx, uint4(0u, 0u, 0u, 0u));
 if (s.w == 0u) return;
 // Frame totals for the menu (dwords 6..9): what the learner measures right now.
 changeCount.InterlockedAdd(24, s.x >> 4); changeCount.InterlockedAdd(28, s.y >> 4);
 changeCount.InterlockedAdd(32, s.z >> 4); changeCount.InterlockedAdd(36, s.w);
 float3 meanErr = float3(s.xyz) / (float(s.w) * 4096.0);
 float4 prev = tileScore[tid.xy];
 float3 sc = (prev.w > 0.5 && all(isfinite(prev.xyz))) ? lerp(prev.xyz, meanErr, 0.25) : meanErr;
 tileScore[tid.xy] = float4(sc, 1.0);
}
)";
class TemporalStability {
 using Res = Microsoft::WRL::ComPtr<ID3D12Resource>;
 // One descriptor region per possible in-flight NR frame, rotated per Run, so
 // the CPU never overwrites a region the GPU may still read (the same rule the
 // main heap's per-slot partitioning follows). Records are gated by the slot
 // count, so at most kRegions NR command lists reference this heap at once.
 static constexpr UINT kRegions = 5;
 // t0 cur, t1 hist, t2 motion, t3 depthCur, t4 depthHist, t5 mvHist, t6 base,
 // t7 residHist, t8 reactive, t9 lut, t10 rawHist, u0 out, u1 depthOut, u2 mvOut, u3 residOut,
 // u4 lutAccum, u5 lutOut, u11 rawOut
 static constexpr UINT kPerRegion = 23; // 11 SRV + 12 UAV (u6 counter, u7/u8 tile sums+scores, u9/u10 class sums+scores, u11 raw history)
 // Root constants: cbuffer P of TemporalStabilityShader, 24 + staticRelax/staticDebug (#5). Checked against the host
 // struct in Run (static_assert); the Tone/Tile shaders declare a shorter copy and read only its head.
 static constexpr UINT kConstants = 26;
 Microsoft::WRL::ComPtr<ID3D12Device> device;
 Microsoft::WRL::ComPtr<ID3D12RootSignature> root;
 Microsoft::WRL::ComPtr<ID3D12PipelineState> pipeline;
 // The same shader built with EDIT_ACCUM=1: every dispatch of presets 10/11 under interleave.
 Microsoft::WRL::ComPtr<ID3D12PipelineState> editPipeline;
 Microsoft::WRL::ComPtr<ID3D12DescriptorHeap> heap;
 Res buffer[2]; // ping-pong: one is history, the other is this frame's output
 Res depthBuffer[2]; // ping-pong depth history, same indexing as buffer[]
 Res mvBuffer[2];    // ping-pong motion history, same indexing as buffer[]
 Res residBuffer[2]; // ping-pong residual history, same indexing as buffer[]
 // Edit accumulation (presets 10/11): the previous frame's raw + learned temporal noise, for the
 // raw-against-raw test. Ping-ponged like the others; written every dispatch by those presets.
 // Allocated at the first Run that needs it, not in Alloc: 2 x RGBA16F at the NR size is 59 MB at
 // 2560x1440, and every other preset - and every user with interleave off - paid for it. Kept
 // until the next size change once made (a Run already recorded may still reference it). Until
 // then t10/u11 are bound to two 1x1 stand-ins, so the table never has a hole.
 Res rawBuffer[2];
 Res rawStandInSrv, rawStandInUav;
 // The model's tonal transfer for v2's fallbacks: 64 bins accumulated on model frames
 // (lutAccum: sum[64], count[64] as uints, then danielblnc's detail sums model[64], raw[64])
 // and resolved into ratios (lutBuf: float[64]).
 // lutBuf is 320 floats: [0..63] that tonemapped curve, [64..127] Edit accumulation's glided
 // log-domain gain and [128..191] its per-bin target, [192..255] the glided detail ratio and
 // [256..319] its target (see ToneLutShader).
 Res lutAccum, lutBuf;
 Microsoft::WRL::ComPtr<ID3D12PipelineState> accumPipeline, lutPipeline, tilePipeline;
 // Self-tuning interleave (preset 8): per-tile error sums and scores, sized in Alloc.
 Res tileAcc, tileScore;
 UINT tilesX = 0, tilesY = 0;
 Res featAcc, featScore; // 64 pixel classes, allocated once
 // Whether each half of the LUT holds a measurement: the tonemapped curve (presets 6/8) and the log
 // half (10/11: gain + detail ratio). Kept apart, and kept across a preset switch while the half
 // was resolved in the last 16 Runs (a quick A/B keeps its curve; one left for longer does not).
 bool lutValid = false;      // the half the current preset reads (what the shader is told)
 bool lutValidTm = false, lutValidLog = false;
 UINT runsSinceTm = ~0u, runsSinceLog = ~0u;
 bool lutAccumClean = false; // the accumulator has been zeroed at least once
 // Adaptive interleave counters (see the shader): zeroed before each dispatch, copied into a
 // readback ring after it, and read three frames later WITHOUT a fence - a slot the GPU has
 // not reached yet simply yields its previous value, and this drives a heuristic, not a
 // picture. Two dwords: fallbacks on a filled frame, pixels in motion on any frame.
 Res counter, counterZero;
 Res counterReadback[4];
 void* counterMapped[4] = {};
 bool counterFilled[4] = {};
 UINT counterSlot = 0;
 float changeFrac = 0.f, motionFrac = 0.f;
 float sharpRatio = 1.f; // preset 7: |hf model| / |hf raw| on the last measured model frame
 bool measuredFilled = false;
 float modelGhostFrac = 0.f; UINT modelGhostSamples = 0;               // dwords 4/5
 UINT modelGhostSkip = 0; // readbacks still in flight when the reading was cleared (ClearModelGhost)
 // Edit accumulation readouts: dword 12 over the samples, and 1 - dword 10 / dword 11.
 float gateRefusedFrac = 0.f, detailKept = -1.f;
 // What the pass ran with last time: a preset (or interleave) change restarts it, because the
 // presets store different things in the residual history and the LUT halves differ.
 float lastExtraTemporal = -1.f, lastInterleaved = -1.f;
 // The next Edit accumulation frame has a valid state but no raw history (reset constant 2).
 bool rawMissing = false;
 float learnedErr[3] = { 0.f, 0.f, 0.f }; bool learnedValid = false; // dwords 6..9
 void EnsureCounters() {
  if (counter) return;
  D3D12_RESOURCE_DESC bd {}; bd.Dimension = D3D12_RESOURCE_DIMENSION_BUFFER; bd.Width = 64; bd.Height = 1;
  bd.DepthOrArraySize = 1; bd.MipLevels = 1; bd.Format = DXGI_FORMAT_UNKNOWN; bd.SampleDesc.Count = 1;
  bd.Layout = D3D12_TEXTURE_LAYOUT_ROW_MAJOR; bd.Flags = D3D12_RESOURCE_FLAG_ALLOW_UNORDERED_ACCESS;
  D3D12_HEAP_PROPERTIES hp {}; hp.Type = D3D12_HEAP_TYPE_DEFAULT;
  Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
      D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr, IID_PPV_ARGS(&counter)));
  bd.Flags = D3D12_RESOURCE_FLAG_NONE;
  hp.Type = D3D12_HEAP_TYPE_UPLOAD;
  Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
      D3D12_RESOURCE_STATE_GENERIC_READ, nullptr, IID_PPV_ARGS(&counterZero)));
  { void* z = nullptr; D3D12_RANGE none { 0, 0 }; Check(counterZero->Map(0, &none, &z)); std::memset(z, 0, 64); counterZero->Unmap(0, nullptr); }
  hp.Type = D3D12_HEAP_TYPE_READBACK;
  for (UINT i = 0; i < 4; ++i) {
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
       D3D12_RESOURCE_STATE_COPY_DEST, nullptr, IID_PPV_ARGS(&counterReadback[i])));
   D3D12_RANGE all { 0, 64 }; Check(counterReadback[i]->Map(0, &all, &counterMapped[i]));
   std::memset(counterMapped[i], 0, 64);
  }
 }
 UINT width = 0, height = 0, index = 0, region = 0, stride = 0;
 bool primed = false; // false => first frame after (re)alloc or reset: pass through
 static void Check(HRESULT hr) { if (FAILED(hr)) throw std::runtime_error("AMD temporal D3D12 error " + std::to_string((UINT)hr)); }
 // The same with the call named: a bare "error 2147500037" (E_FAIL) at the first Run, every
 // launch, on a machine that is not this one (Where Winds Meet report) is not diagnosable.
 static void Check(HRESULT hr, const char* what) {
  if (FAILED(hr)) throw std::runtime_error("AMD temporal D3D12 error " + std::to_string((UINT)hr) + " at " + what);
 }
 static void CheckCompile(HRESULT hr, ID3DBlob* e, const char* what) {
  if (SUCCEEDED(hr)) return;
  std::string msg = "AMD temporal D3D12 error " + std::to_string((UINT)hr) + " compiling " + what;
  if (e && e->GetBufferSize()) msg += ": " + std::string(static_cast<const char*>(e->GetBufferPointer()), e->GetBufferSize());
  throw std::runtime_error(msg);
 }
 // A fully typed SRV format for the motion resource, whatever 2- or 4-channel
 // layout the game supplied (the shader reads .xy). Matches the set AmdPreSr
 // validates before handing motion to the model.
 static DXGI_FORMAT MotionFormat(DXGI_FORMAT f) {
  switch (f) {
  case DXGI_FORMAT_R16G16_TYPELESS: return DXGI_FORMAT_R16G16_FLOAT;
  case DXGI_FORMAT_R32G32_TYPELESS: return DXGI_FORMAT_R32G32_FLOAT;
  case DXGI_FORMAT_R16G16B16A16_TYPELESS: return DXGI_FORMAT_R16G16B16A16_FLOAT;
  case DXGI_FORMAT_R32G32B32A32_TYPELESS: return DXGI_FORMAT_R32G32B32A32_FLOAT;
  default: return f;
  }
 }
 // A readable SRV format for the game's depth resource, whatever typeless or
 // depth-stencil layout it was allocated with. Mirrors AmdPreSr.cpp's own
 // DepthReadFormat (duplicated rather than shared - this class already keeps
 // its own MotionFormat rather than taking a resolved format from the caller).
 static DXGI_FORMAT DepthFormat(DXGI_FORMAT f) {
  switch (f) {
  case DXGI_FORMAT_R32_TYPELESS: case DXGI_FORMAT_D32_FLOAT: return DXGI_FORMAT_R32_FLOAT;
  case DXGI_FORMAT_R16_TYPELESS: case DXGI_FORMAT_D16_UNORM: return DXGI_FORMAT_R16_UNORM;
  case DXGI_FORMAT_R24G8_TYPELESS: case DXGI_FORMAT_D24_UNORM_S8_UINT: return DXGI_FORMAT_R24_UNORM_X8_TYPELESS;
  case DXGI_FORMAT_R32G8X24_TYPELESS: case DXGI_FORMAT_D32_FLOAT_S8X24_UINT: return DXGI_FORMAT_R32_FLOAT_X8X24_TYPELESS;
  default: return f;
  }
 }
 // A readable SRV format for whatever the title allocated its reactive mask as. These
 // are small single- or four-channel textures and engines are inconsistent about the
 // typeless variants, so the unknown case is passed through rather than guessed at.
 static DXGI_FORMAT ReactiveFormat(DXGI_FORMAT f) {
  switch (f) {
  case DXGI_FORMAT_R8_TYPELESS: return DXGI_FORMAT_R8_UNORM;
  case DXGI_FORMAT_R16_TYPELESS: return DXGI_FORMAT_R16_FLOAT;
  case DXGI_FORMAT_R32_TYPELESS: return DXGI_FORMAT_R32_FLOAT;
  case DXGI_FORMAT_R8G8B8A8_TYPELESS: return DXGI_FORMAT_R8G8B8A8_UNORM;
  case DXGI_FORMAT_R16G16B16A16_TYPELESS: return DXGI_FORMAT_R16G16B16A16_FLOAT;
  default: return f;
  }
 }
 // How many components the mask format carries (1..3; alpha never counts - see reactiveAt).
 static unsigned ReactiveChannels(DXGI_FORMAT f) {
  switch (f) {
  case DXGI_FORMAT_R8_TYPELESS: case DXGI_FORMAT_R8_UNORM: case DXGI_FORMAT_R8_UINT: case DXGI_FORMAT_R8_SNORM: case DXGI_FORMAT_R8_SINT:
  case DXGI_FORMAT_R16_TYPELESS: case DXGI_FORMAT_R16_FLOAT: case DXGI_FORMAT_R16_UNORM: case DXGI_FORMAT_R16_UINT: case DXGI_FORMAT_R16_SNORM: case DXGI_FORMAT_R16_SINT:
  case DXGI_FORMAT_R32_TYPELESS: case DXGI_FORMAT_R32_FLOAT: case DXGI_FORMAT_R32_UINT: case DXGI_FORMAT_R32_SINT:
  case DXGI_FORMAT_A8_UNORM: case DXGI_FORMAT_D16_UNORM: case DXGI_FORMAT_D32_FLOAT:
   return 1;
  case DXGI_FORMAT_R8G8_TYPELESS: case DXGI_FORMAT_R8G8_UNORM: case DXGI_FORMAT_R8G8_UINT: case DXGI_FORMAT_R8G8_SNORM: case DXGI_FORMAT_R8G8_SINT:
  case DXGI_FORMAT_R16G16_TYPELESS: case DXGI_FORMAT_R16G16_FLOAT: case DXGI_FORMAT_R16G16_UNORM: case DXGI_FORMAT_R16G16_UINT: case DXGI_FORMAT_R16G16_SNORM: case DXGI_FORMAT_R16G16_SINT:
  case DXGI_FORMAT_R32G32_TYPELESS: case DXGI_FORMAT_R32G32_FLOAT: case DXGI_FORMAT_R32G32_UINT: case DXGI_FORMAT_R32G32_SINT:
   return 2;
  default: return 3;
  }
 }
 static void Barrier(ID3D12GraphicsCommandList* c, ID3D12Resource* r, D3D12_RESOURCE_STATES a, D3D12_RESOURCE_STATES b) {
  if (a == b || !r) return;
  D3D12_RESOURCE_BARRIER v {}; v.Type = D3D12_RESOURCE_BARRIER_TYPE_TRANSITION;
  v.Transition = { r, D3D12_RESOURCE_BARRIER_ALL_SUBRESOURCES, a, b }; c->ResourceBarrier(1, &v);
 }
 void Alloc(UINT w, UINT h) {
  D3D12_HEAP_PROPERTIES hp {}; hp.Type = D3D12_HEAP_TYPE_DEFAULT;
  D3D12_RESOURCE_DESC rd {}; rd.Dimension = D3D12_RESOURCE_DIMENSION_TEXTURE2D; rd.Width = w; rd.Height = h;
  rd.DepthOrArraySize = 1; rd.MipLevels = 1; rd.Format = DXGI_FORMAT_R16G16B16A16_FLOAT; rd.SampleDesc.Count = 1;
  rd.Flags = D3D12_RESOURCE_FLAG_ALLOW_UNORDERED_ACCESS;
  D3D12_RESOURCE_DESC drd = rd; drd.Format = DXGI_FORMAT_R32_FLOAT;
  D3D12_RESOURCE_DESC mrd = rd; mrd.Format = DXGI_FORMAT_R16G16_FLOAT;
  for (int i = 0; i < 2; ++i) {
   buffer[i].Reset();
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &rd,
       D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr, IID_PPV_ARGS(&buffer[i])), "colour history buffer");
   depthBuffer[i].Reset();
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &drd,
       D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr, IID_PPV_ARGS(&depthBuffer[i])), "depth history buffer");
   mvBuffer[i].Reset();
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &mrd,
       D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr, IID_PPV_ARGS(&mvBuffer[i])), "motion history buffer");
   residBuffer[i].Reset();
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &rd,
       D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr, IID_PPV_ARGS(&residBuffer[i])), "residual history buffer");
   rawBuffer[i].Reset(); // made again at the first Edit accumulation Run at this size (EnsureRaw)
  }
  if (!lutAccum) {
   // 4 x 64 uints: sum and count per bin, and danielblnc's detail sums (model, raw) per bin.
   D3D12_RESOURCE_DESC bd {}; bd.Dimension = D3D12_RESOURCE_DIMENSION_BUFFER; bd.Width = 1024; bd.Height = 1;
   bd.DepthOrArraySize = 1; bd.MipLevels = 1; bd.Format = DXGI_FORMAT_UNKNOWN; bd.SampleDesc.Count = 1;
   bd.Layout = D3D12_TEXTURE_LAYOUT_ROW_MAJOR; bd.Flags = D3D12_RESOURCE_FLAG_ALLOW_UNORDERED_ACCESS;
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
       D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr, IID_PPV_ARGS(&lutAccum)), "tone accumulator buffer");
   bd.Width = 1280; // 320 floats: the tonemapped curve, Edit accumulation's log gain and its detail ratio (shown + target each)
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
       D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr, IID_PPV_ARGS(&lutBuf)), "tone lut buffer");
   lutAccumClean = false;
  }
  lutValid = lutValidTm = lutValidLog = false;
  {
   tilesX = (w + 15) / 16; tilesY = (h + 15) / 16;
   D3D12_RESOURCE_DESC bd {}; bd.Dimension = D3D12_RESOURCE_DIMENSION_BUFFER; bd.Width = UINT64(tilesX) * tilesY * 16; bd.Height = 1;
   bd.DepthOrArraySize = 1; bd.MipLevels = 1; bd.Format = DXGI_FORMAT_UNKNOWN; bd.SampleDesc.Count = 1;
   bd.Layout = D3D12_TEXTURE_LAYOUT_ROW_MAJOR; bd.Flags = D3D12_RESOURCE_FLAG_ALLOW_UNORDERED_ACCESS;
   tileAcc.Reset();
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
       D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr, IID_PPV_ARGS(&tileAcc)), "tile accumulator buffer");
   D3D12_RESOURCE_DESC td = rd; td.Width = tilesX; td.Height = tilesY; td.Format = DXGI_FORMAT_R32G32B32A32_FLOAT;
   tileScore.Reset();
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &td,
       D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr, IID_PPV_ARGS(&tileScore)), "tile score buffer");
   if (!featAcc) {
    bd.Width = 64 * 16;
    Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &bd,
        D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr, IID_PPV_ARGS(&featAcc)), "feature accumulator buffer");
    td.Width = 64; td.Height = 1;
    Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &td,
        D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr, IID_PPV_ARGS(&featScore)));
   }
  }
  width = w; height = h; index = 0; primed = false;
 }
 // The raw history, made at the first Edit accumulation Run at this size. Returns true when it was
 // made now: its contents are undefined, so that frame must not read it.
 bool EnsureRaw() {
  if (rawBuffer[0] && rawBuffer[1]) return false;
  D3D12_HEAP_PROPERTIES hp {}; hp.Type = D3D12_HEAP_TYPE_DEFAULT;
  D3D12_RESOURCE_DESC rd {}; rd.Dimension = D3D12_RESOURCE_DIMENSION_TEXTURE2D; rd.Width = width; rd.Height = height;
  rd.DepthOrArraySize = 1; rd.MipLevels = 1; rd.Format = DXGI_FORMAT_R16G16B16A16_FLOAT; rd.SampleDesc.Count = 1;
  rd.Flags = D3D12_RESOURCE_FLAG_ALLOW_UNORDERED_ACCESS;
  for (int i = 0; i < 2; ++i)
   Check(device->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &rd,
       D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr, IID_PPV_ARGS(&rawBuffer[i])), "raw history buffer");
  return true;
 }
 public:
 TemporalStability(ID3D12Device* d) : device(d) {
  D3D12_DESCRIPTOR_RANGE ranges[2] = { { D3D12_DESCRIPTOR_RANGE_TYPE_SRV, 11, 0, 0, 0 },
                                       { D3D12_DESCRIPTOR_RANGE_TYPE_UAV, 12, 0, 0, 11 } };
  D3D12_ROOT_PARAMETER params[2] {};
  params[0].ParameterType = D3D12_ROOT_PARAMETER_TYPE_DESCRIPTOR_TABLE; params[0].DescriptorTable = { 2, ranges };
  params[1].ParameterType = D3D12_ROOT_PARAMETER_TYPE_32BIT_CONSTANTS; params[1].Constants = { 0, 0, kConstants };
  D3D12_STATIC_SAMPLER_DESC samp {};
  samp.Filter = D3D12_FILTER_MIN_MAG_MIP_LINEAR;
  samp.AddressU = samp.AddressV = samp.AddressW = D3D12_TEXTURE_ADDRESS_MODE_CLAMP;
  samp.ShaderRegister = 0; samp.RegisterSpace = 0; samp.ShaderVisibility = D3D12_SHADER_VISIBILITY_ALL;
  D3D12_ROOT_SIGNATURE_DESC rd {}; rd.NumParameters = 2; rd.pParameters = params;
  rd.NumStaticSamplers = 1; rd.pStaticSamplers = &samp;
  Microsoft::WRL::ComPtr<ID3DBlob> b, e;
  Check(D3D12SerializeRootSignature(&rd, D3D_ROOT_SIGNATURE_VERSION_1, &b, &e), "root signature serialize");
  Check(d->CreateRootSignature(0, b->GetBufferPointer(), b->GetBufferSize(), IID_PPV_ARGS(&root)), "root signature");
  CheckCompile(DlssNr::SysCompiler::Compile(TemporalStabilityShader, sizeof(TemporalStabilityShader), "AMD temporal stability", nullptr,
                          nullptr, "main", "cs_5_0", 0, 0, &b, &e), e.Get(), "temporal stability");
  D3D12_COMPUTE_PIPELINE_STATE_DESC pd {}; pd.pRootSignature = root.Get(); pd.CS = { b->GetBufferPointer(), b->GetBufferSize() };
  Check(d->CreateComputePipelineState(&pd, IID_PPV_ARGS(&pipeline)), "temporal stability pipeline");
  {
   const D3D_SHADER_MACRO editDefines[] = { { "EDIT_ACCUM", "1" }, { nullptr, nullptr } };
   CheckCompile(DlssNr::SysCompiler::Compile(TemporalStabilityShader, sizeof(TemporalStabilityShader), "AMD temporal stability (edit accumulation)",
                           editDefines, nullptr, "main", "cs_5_0", 0, 0, &b, &e), e.Get(), "temporal stability (edit accumulation)");
   pd.CS = { b->GetBufferPointer(), b->GetBufferSize() };
   Check(d->CreateComputePipelineState(&pd, IID_PPV_ARGS(&editPipeline)), "temporal stability pipeline (edit accumulation)");
  }
  CheckCompile(DlssNr::SysCompiler::Compile(ToneAccumulateShader, sizeof(ToneAccumulateShader), "AMD tone accumulate", nullptr,
                          nullptr, "main", "cs_5_0", 0, 0, &b, &e), e.Get(), "tone accumulate");
  pd.CS = { b->GetBufferPointer(), b->GetBufferSize() };
  Check(d->CreateComputePipelineState(&pd, IID_PPV_ARGS(&accumPipeline)), "tone accumulate pipeline");
  CheckCompile(DlssNr::SysCompiler::Compile(ToneLutShader, sizeof(ToneLutShader), "AMD tone lut", nullptr,
                          nullptr, "main", "cs_5_0", 0, 0, &b, &e), e.Get(), "tone lut");
  pd.CS = { b->GetBufferPointer(), b->GetBufferSize() };
  Check(d->CreateComputePipelineState(&pd, IID_PPV_ARGS(&lutPipeline)), "tone lut pipeline");
  CheckCompile(DlssNr::SysCompiler::Compile(TileScoreShader, sizeof(TileScoreShader), "AMD tile score", nullptr,
                          nullptr, "main", "cs_5_0", 0, 0, &b, &e), e.Get(), "tile score");
  pd.CS = { b->GetBufferPointer(), b->GetBufferSize() };
  Check(d->CreateComputePipelineState(&pd, IID_PPV_ARGS(&tilePipeline)), "tile score pipeline");
  { // t10/u11 stand-ins for the Runs that have no raw history: 1x1, one for each view kind, each
    // left in the state its view needs for good.
   D3D12_HEAP_PROPERTIES hp {}; hp.Type = D3D12_HEAP_TYPE_DEFAULT;
   D3D12_RESOURCE_DESC td {}; td.Dimension = D3D12_RESOURCE_DIMENSION_TEXTURE2D; td.Width = 1; td.Height = 1;
   td.DepthOrArraySize = 1; td.MipLevels = 1; td.Format = DXGI_FORMAT_R16G16B16A16_FLOAT; td.SampleDesc.Count = 1;
   td.Flags = D3D12_RESOURCE_FLAG_ALLOW_UNORDERED_ACCESS;
   Check(d->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &td, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, nullptr,
                                    IID_PPV_ARGS(&rawStandInSrv)), "raw history stand-in (SRV)");
   Check(d->CreateCommittedResource(&hp, D3D12_HEAP_FLAG_NONE, &td, D3D12_RESOURCE_STATE_UNORDERED_ACCESS, nullptr,
                                    IID_PPV_ARGS(&rawStandInUav)), "raw history stand-in (UAV)");
  }
  D3D12_DESCRIPTOR_HEAP_DESC hd {}; hd.Type = D3D12_DESCRIPTOR_HEAP_TYPE_CBV_SRV_UAV; hd.NumDescriptors = kRegions * kPerRegion;
  hd.Flags = D3D12_DESCRIPTOR_HEAP_FLAG_SHADER_VISIBLE;
  Check(d->CreateDescriptorHeap(&hd, IID_PPV_ARGS(&heap)), "descriptor heap");
  stride = d->GetDescriptorHandleIncrementSize(D3D12_DESCRIPTOR_HEAP_TYPE_CBV_SRV_UAV);
 }
 // Applied at the next Run: the previous result is not reused (camera cut, NR
 // disabled/re-enabled, resolution change).
 void ResetHistory() { primed = false; }
 // For the lmxxf carry (preset 9): the host writes the network's fresh edit into the residual
 // history BEFORE Run, so the buffers must exist for the size first, and it needs to know
 // which of the two residual buffers Run will read (history) and which it will write (next).
 void Prepare(UINT w, UINT h) { if (width != w || height != h) Alloc(w, h); }
 ID3D12Resource* ResidualHistory() const { return residBuffer[index].Get(); }
 ID3D12Resource* ResidualNext() const { return residBuffer[index ^ 1].Get(); }
 // The previous frame's motion (render pixels, scaled), as the shader wrote it: the lmxxf
 // backend chains it behind this frame's vectors when the network last ran two frames ago.
 ID3D12Resource* MotionHistory() const { return mvBuffer[index].Get(); }
 // After Run has flipped the index: the motion of the frame BEFORE the one just run.
 ID3D12Resource* MotionBeforeThis() const { return mvBuffer[index ^ 1].Get(); }
 bool Primed() const { return primed; }
 // Adaptive interleave: the last readings, three frames old. ChangeFraction is meaningful
 // only when MeasuredFilled (a model frame has no fallbacks to count).
 float ChangeFraction() const { return changeFrac; }
 float MotionFraction() const { return motionFrac; }
 bool MeasuredFilled() const { return measuredFilled; }
 float SharpRatio() const { return sharpRatio; }
 float ModelGhostFraction() const { return modelGhostFrac; }
 UINT ModelGhostSamples() const { return modelGhostSamples; }
 // (P3, 0.3.3.2) Drops the model-frame ghost reading and the readbacks still in flight (the ring's four
 // slots), so a reading taken under an earlier interleave, preset or model history is never shown.
 void ClearModelGhost() { modelGhostFrac = 0.f; modelGhostSamples = 0; modelGhostSkip = 4; }
 bool LearnedValid() const { return learnedValid; }
 float LearnedError(int k) const { return learnedErr[k]; }
 // Edit accumulation (presets 10/11). DepthHistory: the depth the last Run wrote - before this
 // frame's Run it is frame N-1's, the frame lmxxf's fresh edit belongs to (R32_FLOAT, left in
 // NON_PIXEL_SHADER_RESOURCE between Runs). GateRefusedFraction: pixels refused by the raw test
 // alone. DetailKept: how much of the model's local detail the danielblnc fit reproduces, -1
 // until a model frame was measured. LutValid: the model's transfer has been measured.
 ID3D12Resource* DepthHistory() const { return depthBuffer[index].Get(); }
 float GateRefusedFraction() const { return gateRefusedFrac; }
 float DetailKept() const { return detailKept; }
 bool LutValid() const { return lutValid; }
 // Returns the stabilised colour (one of the ping-pong buffers), or `colour`
 // itself when the pass is inert. `colourState`/`motionState`/`depthState` are
 // restored.
 ID3D12Resource* Run(ID3D12GraphicsCommandList* c, ID3D12Resource* colour, D3D12_RESOURCE_STATES colourState,
                     ID3D12Resource* motion, D3D12_RESOURCE_STATES motionState,
                     ID3D12Resource* depth, D3D12_RESOURCE_STATES depthState, UINT w, UINT h,
                     float mvScaleX, float mvScaleY, float alpha, bool reset, float ghostReject = 1.f,
                     UINT mode = 0, float threshold = 0.08f, float interleaved = 0.f,
                     float detailScale = 0.5f, float modelFrame = 0.f,
                     float sharpFill = 0.f, float debugView = 0.f,
                     float extraTemporal = 0.f, ID3D12Resource* baseline = nullptr,
                     float residualTemporal = 0.f, float residualCap = 0.25f,
                     float depthInv = 0.f, float heldGhostBound = 0.f,
                     ID3D12Resource* reactiveMask = nullptr, float jitterDx = 0.f, float jitterDy = 0.f,
                     float sharpGain = 0.f, float staticRelax = 0.f, float staticDebug = 0.f) {
  if (!c || !colour || !motion || !depth || !w || !h) return colour;
  if (width != w || height != h) Alloc(w, h);
  const bool accumNow = interleaved > 0.5f && extraTemporal > 9.5f;
  const bool logHalf = extraTemporal > 9.5f;
  if (runsSinceTm != ~0u) ++runsSinceTm;
  if (runsSinceLog != ~0u) ++runsSinceLog;
  // A preset or an interleave switch restarts the pass: the presets store different things in
  // the residual history (a picture's edit, a tonal edit, a gain/slope state) and use different
  // halves of the LUT, and reading one as another for a frame is a flash. `historyReset` on the
  // host does not include a settings change (that would force the runtime to rebuild its own
  // history too), so the restart is decided here. The restart frame now also empties the
  // residual the next frame reads (the shader's pass-through writes it), which is what flashed
  // after 10 -> 6 and 10 -> 8.
  //
  // EXCEPT lmxxf's two carries. Classic carry (9) and Edit accumulation (11) store the same thing
  // - a linear edit, alpha = the geometric keep - so 11 -> 9 goes straight on, and 9 -> 11 goes on
  // with one frame that trusts the geometry alone while the raw history 9 never wrote is made
  // (reset constant 2). Restarting them cost every toggle of Model interleave on lmxxf a frame of
  // raw and then about ten frames of the edit fading back in from zero.
  //
  // The LUT half the new preset reads is kept if it was resolved in the last 16 Runs (an A/B
  // switched back and forth keeps its curve) and dropped otherwise (it describes another scene).
  if (extraTemporal != lastExtraTemporal || interleaved != lastInterleaved)
  {
   const bool lmxxfPair = interleaved > 0.5f && lastInterleaved > 0.5f &&
                          ((extraTemporal == 11.f && lastExtraTemporal == 9.f) || (extraTemporal == 9.f && lastExtraTemporal == 11.f));
   if (lmxxfPair) { if (accumNow) rawMissing = true; }
   else primed = false;
   if (logHalf) lutValidLog = lutValidLog && runsSinceLog < 16u;
   else lutValidTm = lutValidTm && runsSinceTm < 16u;
   lastExtraTemporal = extraTemporal; lastInterleaved = interleaved;
  }
  lutValid = logHalf ? lutValidLog : lutValidTm;
  // The raw history, at the first Edit accumulation Run at this size; a frame that made it reads
  // none (it is either a restart, or it runs as reset constant 2).
  const bool rawFresh = accumNow && EnsureRaw();
  EnsureCounters();
  ID3D12Resource* hist = buffer[index].Get();
  ID3D12Resource* out = buffer[index ^ 1].Get();
  ID3D12Resource* depthHistRes = depthBuffer[index].Get();
  ID3D12Resource* depthOut = depthBuffer[index ^ 1].Get();
  ID3D12Resource* mvHistRes = mvBuffer[index].Get();
  ID3D12Resource* mvOut = mvBuffer[index ^ 1].Get();
  ID3D12Resource* residHistRes = residBuffer[index].Get();
  ID3D12Resource* residOut = residBuffer[index ^ 1].Get();
  ID3D12Resource* rawHistRes = accumNow ? rawBuffer[index].Get() : rawStandInSrv.Get();
  ID3D12Resource* rawOut = accumNow ? rawBuffer[index ^ 1].Get() : rawStandInUav.Get();
  // With the preset off there is no baseline to bind, so the colour stands in. Nothing
  // reads t6/t7 on those paths; this exists so the table is never left with a hole, which
  // is a device-removal on some drivers rather than a quietly ignored descriptor.
  ID3D12Resource* baseRes = baseline ? baseline : colour;
  const bool passthrough = reset || !primed || alpha <= 0.f;
  // 1 = pass through / no history; 2 = Edit accumulation with a valid state but no raw history.
  const UINT resetConst = passthrough ? 1u : ((accumNow && (rawMissing || rawFresh)) ? 2u : 0u);
  if (accumNow) rawMissing = false;
  const UINT base = region * kPerRegion;
  region = (region + 1) % kRegions;
  auto cpu = heap->GetCPUDescriptorHandleForHeapStart();
  cpu.ptr += static_cast<SIZE_T>(base) * stride;
  auto addSrv = [&](ID3D12Resource* r, DXGI_FORMAT fmt) {
   D3D12_SHADER_RESOURCE_VIEW_DESC s {}; s.Format = fmt; s.ViewDimension = D3D12_SRV_DIMENSION_TEXTURE2D;
   s.Shader4ComponentMapping = D3D12_DEFAULT_SHADER_4_COMPONENT_MAPPING; s.Texture2D.MipLevels = 1;
   device->CreateShaderResourceView(r, &s, cpu); cpu.ptr += stride;
  };
  addSrv(colour, DXGI_FORMAT_R16G16B16A16_FLOAT);
  addSrv(hist, DXGI_FORMAT_R16G16B16A16_FLOAT);
  addSrv(motion, MotionFormat(motion->GetDesc().Format));
  addSrv(depth, DepthFormat(depth->GetDesc().Format));
  addSrv(depthHistRes, DXGI_FORMAT_R32_FLOAT);
  addSrv(mvHistRes, DXGI_FORMAT_R16G16_FLOAT);
  addSrv(baseRes, DXGI_FORMAT_R16G16B16A16_FLOAT);
  addSrv(residHistRes, DXGI_FORMAT_R16G16B16A16_FLOAT);
  // t8. When the title publishes no mask the colour texture stands in so the table
  // never has a hole - an unbound descriptor is a device removal on some drivers
  // rather than a quietly ignored read - and reactiveAvail=0 keeps the shader off it.
  if (reactiveMask) addSrv(reactiveMask, ReactiveFormat(reactiveMask->GetDesc().Format));
  else addSrv(colour, DXGI_FORMAT_R16G16B16A16_FLOAT);
  { // t9: the tone LUT, a raw buffer of 320 floats (tonemapped curve, log gain + target, detail ratio + target)
   D3D12_SHADER_RESOURCE_VIEW_DESC s {}; s.Format = DXGI_FORMAT_R32_TYPELESS; s.ViewDimension = D3D12_SRV_DIMENSION_BUFFER;
   s.Shader4ComponentMapping = D3D12_DEFAULT_SHADER_4_COMPONENT_MAPPING; s.Buffer.FirstElement = 0; s.Buffer.NumElements = 320;
   s.Buffer.Flags = D3D12_BUFFER_SRV_FLAG_RAW;
   device->CreateShaderResourceView(lutBuf.Get(), &s, cpu); cpu.ptr += stride;
  }
  // t10: the raw history. Bound on every preset so the table has no hole (the order of these
  // descriptors is load-bearing: a hole or a misorder is a device removal, not a warning); the
  // 1x1 stand-in while no Edit accumulation Run has made the real one.
  addSrv(rawHistRes, DXGI_FORMAT_R16G16B16A16_FLOAT);
  auto addUav = [&](ID3D12Resource* r, DXGI_FORMAT fmt) {
   D3D12_UNORDERED_ACCESS_VIEW_DESC u {}; u.Format = fmt; u.ViewDimension = D3D12_UAV_DIMENSION_TEXTURE2D;
   device->CreateUnorderedAccessView(r, nullptr, &u, cpu); cpu.ptr += stride;
  };
  addUav(out, DXGI_FORMAT_R16G16B16A16_FLOAT);
  addUav(depthOut, DXGI_FORMAT_R32_FLOAT);
  addUav(mvOut, DXGI_FORMAT_R16G16_FLOAT);
  addUav(residOut, DXGI_FORMAT_R16G16B16A16_FLOAT);
  auto addUavRaw = [&](ID3D12Resource* r, UINT elements) {
   D3D12_UNORDERED_ACCESS_VIEW_DESC u {}; u.Format = DXGI_FORMAT_R32_TYPELESS; u.ViewDimension = D3D12_UAV_DIMENSION_BUFFER;
   u.Buffer.FirstElement = 0; u.Buffer.NumElements = elements; u.Buffer.Flags = D3D12_BUFFER_UAV_FLAG_RAW;
   device->CreateUnorderedAccessView(r, nullptr, &u, cpu); cpu.ptr += stride;
  };
  addUavRaw(lutAccum.Get(), 256);
  addUavRaw(lutBuf.Get(), 320);
  // u6, always bound so the table has no hole. ALL 16 dwords: this view was 4 elements over the
  // 64-byte buffer since f59cd722, so every write from dword 4 on - the Model-frame ghost meter,
  // the Self-tuning totals - was an out-of-bounds UAV write, discarded without a word.
  addUavRaw(counter.Get(), 16);
  addUavRaw(tileAcc.Get(), tilesX * tilesY * 4); // u7
  addUav(tileScore.Get(), DXGI_FORMAT_R32G32B32A32_FLOAT); // u8
  addUavRaw(featAcc.Get(), 64 * 4); // u9
  addUav(featScore.Get(), DXGI_FORMAT_R32G32B32A32_FLOAT); // u10
  addUav(rawOut, DXGI_FORMAT_R16G16B16A16_FLOAT); // u11
  Barrier(c, colour, colourState, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, motion, motionState, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, depth, depthState, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, out, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
  Barrier(c, depthOut, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
  Barrier(c, mvOut, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
  Barrier(c, residOut, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
  if (accumNow) Barrier(c, rawOut, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
  auto hh = heap.Get(); c->SetDescriptorHeaps(1, &hh);
  c->SetComputeRootSignature(root.Get()); c->SetPipelineState(accumNow ? editPipeline.Get() : pipeline.Get());
  auto gpu = heap->GetGPUDescriptorHandleForHeapStart(); gpu.ptr += static_cast<UINT64>(base) * stride;
  c->SetComputeRootDescriptorTable(0, gpu);
  struct { UINT w, h; float alpha; UINT reset; float sx, sy; float ghostReject; UINT mode; float threshold; float interleaved; float detailScale; float modelFrame; float sharpFill; float debugView; float extraTemporal; float residualTemporal; float residualCap; float depthInv; float heldGhostBound; float reactiveAvail; float lutAvail; float jitterDx, jitterDy; float sharpGain; float staticRelax; float staticDebug; } cb {
   w, h, alpha, resetConst, mvScaleX, mvScaleY, ghostReject, mode, threshold, interleaved, detailScale, modelFrame, sharpFill, debugView, extraTemporal, residualTemporal, residualCap, depthInv, heldGhostBound, reactiveMask ? float(ReactiveChannels(reactiveMask->GetDesc().Format)) : 0.f, lutValid ? 1.f : 0.f, jitterDx, jitterDy, sharpGain, staticRelax, staticDebug };
  static_assert(sizeof(cb) == 4u * kConstants, "TemporalStability root constants");
  c->SetComputeRoot32BitConstants(1, kConstants, &cb, 0);
  const bool countThisFrame = interleaved > 0.5f && !passthrough;
  if (countThisFrame) {
   Barrier(c, counter.Get(), D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_COPY_DEST);
   c->CopyBufferRegion(counter.Get(), 0, counterZero.Get(), 0, 64);
   Barrier(c, counter.Get(), D3D12_RESOURCE_STATE_COPY_DEST, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
  }
  c->Dispatch((w + 7) / 8, (h + 7) / 8, 1);
  // v2, model frame: measure the model's tonal transfer for the filled frames' fallbacks.
  // The first time through only zeroes the accumulator (its initial contents are
  // undefined); every model frame after that accumulates and resolves.
  // Edit accumulation (10/11) measures its log form on every frame an answer arrived - a
  // danielblnc model frame, an lmxxf consume - and RESOLVES EVERY (primed) FRAME, so the shown
  // curve glides instead of stepping. The accumulator is zeroed by every resolve, so a frame
  // with no answer resolves zero sums and only glides.
  const bool toneTm  = extraTemporal > 5.5f && extraTemporal < 9.5f && modelFrame > 0.f && baseline != nullptr && !passthrough;
  const bool toneLog = interleaved > 0.5f && extraTemporal > 9.5f && baseline != nullptr && !passthrough;
  const bool freshTone = toneTm || (toneLog && (extraTemporal < 10.5f ? modelFrame > 0.f : residualTemporal > 0.5f));
  if (toneTm || toneLog) {
   Barrier(c, lutBuf.Get(), D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
   D3D12_RESOURCE_BARRIER ub {}; ub.Type = D3D12_RESOURCE_BARRIER_TYPE_UAV; ub.UAV.pResource = lutAccum.Get();
   if (freshTone && lutAccumClean) {
    c->SetPipelineState(accumPipeline.Get());
    c->Dispatch(((w + 1) / 2 + 7) / 8, ((h + 1) / 2 + 7) / 8, 1); // one thread per sample (every other pixel)
    c->ResourceBarrier(1, &ub);
   }
   c->SetPipelineState(lutPipeline.Get());
   c->Dispatch(1, 1, 1);
   c->ResourceBarrier(1, &ub);
   Barrier(c, lutBuf.Get(), D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
   if (freshTone && lutAccumClean) { lutValid = true; (toneLog ? lutValidLog : lutValidTm) = true; }
   (toneLog ? runsSinceLog : runsSinceTm) = 0u;
   lutAccumClean = true;
  }
  // Self-tuning interleave: fold this model frame's candidate errors into the tile scores
  // (and clear both on a reset frame, which is what the first frame after Alloc is).
  // Preset 8 ONLY: this read `extraTemporal > 7.5` and so also ran - and folded nothing into
  // everything - on presets 9, 10 and 11.
  if (extraTemporal > 7.5f && extraTemporal < 8.5f && (modelFrame > 0.f || passthrough)) {
   D3D12_RESOURCE_BARRIER tb[4] {};
   tb[0].Type = D3D12_RESOURCE_BARRIER_TYPE_UAV; tb[0].UAV.pResource = tileAcc.Get();
   tb[1].Type = D3D12_RESOURCE_BARRIER_TYPE_UAV; tb[1].UAV.pResource = tileScore.Get();
   tb[2].Type = D3D12_RESOURCE_BARRIER_TYPE_UAV; tb[2].UAV.pResource = featAcc.Get();
   tb[3].Type = D3D12_RESOURCE_BARRIER_TYPE_UAV; tb[3].UAV.pResource = featScore.Get();
   c->ResourceBarrier(4, tb);
   c->SetPipelineState(tilePipeline.Get());
   c->Dispatch((std::max)((tilesX + 7) / 8, 8u), (tilesY + 7) / 8, 1); // >= 64 threads in x for the classes
   c->ResourceBarrier(4, tb);
  }
  // The counters are read back AFTER the tile pass, which adds the self-tuning totals.
  if (countThisFrame) {
   Barrier(c, counter.Get(), D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_COPY_SOURCE);
   c->CopyBufferRegion(counterReadback[counterSlot].Get(), 0, counter.Get(), 0, 64);
   Barrier(c, counter.Get(), D3D12_RESOURCE_STATE_COPY_SOURCE, D3D12_RESOURCE_STATE_UNORDERED_ACCESS);
   counterFilled[counterSlot] = modelFrame <= 0.f && extraTemporal > 5.5f;
   const UINT oldest = (counterSlot + 1) % 4;
   const UINT* v = static_cast<const UINT*>(counterMapped[oldest]);
   const float samples = float((w / 2) * (h / 2));
   changeFrac = samples > 0.f ? float(v[0]) / samples : 0.f;
   motionFrac = samples > 0.f ? float(v[1]) / samples : 0.f;
   measuredFilled = counterFilled[oldest];
   // The model's high band over the raw's, from the last measured model frame.
   if (v[3] > 0u) sharpRatio = float(v[2]) / float(v[3]);
   // Model-frame ghost meter and the self-tuning totals: model frames only.
   if (modelGhostSkip > 0u) --modelGhostSkip; // written before ClearModelGhost
   else if (v[5] > 0u) { modelGhostFrac = float(v[4]) / float(v[5]); modelGhostSamples = v[5]; }
   if (v[9] > 0u) {
    for (int k = 0; k < 3; ++k) learnedErr[k] = float(v[6 + k]) * 16.f / (float(v[9]) * 4096.f);
    learnedValid = true;
   }
   // Edit accumulation: refused by the raw test alone (dword 12), and the share of the model's
   // local detail the danielblnc fit reproduces (1 - missed / total, dwords 10/11; model frames).
   gateRefusedFrac = samples > 0.f ? float(v[12]) / samples : 0.f;
   if (v[11] > 0u) detailKept = 1.f - float(v[10]) / float(v[11]);
   counterSlot = oldest;
  }
  Barrier(c, out, D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, depthOut, D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, mvOut, D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, residOut, D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  if (accumNow) Barrier(c, rawOut, D3D12_RESOURCE_STATE_UNORDERED_ACCESS, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE);
  Barrier(c, colour, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, colourState);
  Barrier(c, motion, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, motionState);
  Barrier(c, depth, D3D12_RESOURCE_STATE_NON_PIXEL_SHADER_RESOURCE, depthState);
  index ^= 1; // this frame's output becomes next frame's history
  primed = true;
  return out;
 }
};
}
