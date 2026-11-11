//! Video recipes wired the way the owner's DaSiWa workflows do it (LTX OmniForge, Wan 2.2
//! FastFidelity, MiniMax H3 MythicAlchemy), not the ComfyUI templates. One intent,
//! `recipeId: "video-generation"`, discriminated by `family`.
use crate::jobs::{comfy_model_name, model_name, safe_choice, safe_output_prefix, valid_options};
use serde_json::{json, Value};

pub(crate) const FAMILIES: [&str; 4] = ["ltx-2", "wan", "minimax-h3", "minimax-h3-hyperflow"];
/// The HyperFlow Flash GGUF variant runs the same DaSiWa Director graph with a different loader and schedule.
pub(crate) fn is_h3(family: &str) -> bool {
    family == "minimax-h3" || family == "minimax-h3-hyperflow"
}
const FIELDS: [&str; 17] = [
    "recipeId",
    "version",
    "family",
    "positivePrompt",
    "negativePrompt",
    "model",
    "textEncoder",
    "vae",
    "seed",
    "width",
    "height",
    "frames",
    "frameRate",
    "steps",
    "cfg",
    "sampler",
    "scheduler",
];
const OPTIONAL: [&str; 12] = [
    "faceRefine",
    "enhancedPreview",
    "latentUpscale",
    "videoPost",
    "outputPrefix",
    "sourceVideo",
    "output",
    "loras",
    "options",
    "firstFrame",
    "lastFrame",
    "chunks",
];
/// DaSiWa Enhanced Video Combine enums.
pub(crate) const CODECS: [&str; 5] = ["Auto", "AV1", "VP9", "H.265 (HEVC)", "H.264"];
pub(crate) const CONTAINERS: [&str; 6] = [
    "Auto",
    "WebM",
    "MKV",
    "MP4",
    "Animated WebP",
    "Animated AVIF",
];
pub(crate) const BIT_DEPTHS: [&str; 3] = ["Auto", "8-bit", "10-bit"];
pub(crate) const AUDIO_CODECS: [&str; 4] = ["Auto", "AAC", "Opus", "MP3"];
pub(crate) const AUDIO_BITRATES: [&str; 7] = ["64k", "96k", "128k", "160k", "192k", "256k", "320k"];
const H3_MODES: [&str; 5] = ["T2VA", "I2VA", "L2VA", "FL2VA", "REF2VA"];
/// DaSiWa Director REF2VA lanes (slots per lane) and media modes of a video item.
const H3_LANES: [(&str, u64); 3] = [("image", 9), ("video", 3), ("audio", 3)];
const H3_MEDIA_MODES: [&str; 3] = ["video", "audio", "video_audio"];
/// Director `timeline_data.resolution.input_scaling` values (`helper_minimax_h3_director.py::INPUT_SCALING_MODES`).
const H3_INPUT_SCALING: [&str; 7] = [
    "Off",
    "Auto",
    "Target",
    "Fit",
    "Fill and crop",
    "Fit and pad",
    "Long side with divisible crop",
];
/// Every class the three graphs can emit; prepare() checks each against object_info.
pub(crate) const VIDEO_NODES: [&str; 39] = [
    "ModelPreviewOverrideKJ",
    "DaSiWaH3TiledUpscale",
    "DualCLIPLoader",
    "LoraLoaderModelOnly",
    "RandomNoise",
    "KSamplerSelect",
    "BasicScheduler",
    "CFGGuider",
    "BasicGuider",
    "SamplerCustomAdvanced",
    "KSamplerAdvanced",
    "ModelSamplingSD3",
    "ImageScale",
    "LoadImage",
    "LoadVideo",
    "GetVideoComponents",
    "ImageFromBatch",
    "LTXVConditioning",
    "EmptyLTXVLatentVideo",
    "LTXVEmptyLatentAudio",
    "LTXVPreprocess",
    "LTXVAddGuide",
    "LTXVCropGuides",
    "LTXVConcatAVLatent",
    "LTXVSeparateAVLatent",
    "LTXVAudioVAEDecode",
    "LatentUpscaleModelLoader",
    "LTXVLatentUpsampler",
    "LTXVChunkFeedForward",
    "WanImageToVideo",
    "WanFirstLastFrameToVideo",
    "WanChunkFeedForward",
    "MiniMaxH3Director",
    "MiniMaxH3DirectorGuide",
    "HyperFlowGGUFLoader",
    "HyperFlowSigmas",
    "MiniMaxH3SigmaShift",
    "MiniMaxChunkFeedForward",
    "DaSiWa_EnhancedVideoCombine",
];
pub(crate) const H3_CONTINUITY_NODES: [&str; 6] = [
    "DaSiWaH3ContinuitySegmentPrepare",
    "DaSiWaH3ContinuitySegmentDecode",
    "DaSiWaH3ContinuityPublish",
    "DaSiWaH3ClipAssemble",
    "DaSiWaH3TransitionGuide",
    "DaSiWaH3TransitionRender",
];

pub(crate) fn is_video(intent: &Value) -> bool {
    intent["recipeId"] == "video-generation"
        || crate::jobs_video_post::is_enhance(intent)
        || is_join(intent)
        || crate::jobs_face_refine::is_face_refine(intent)
}

pub(crate) fn is_join(intent: &Value) -> bool {
    intent["recipeId"] == "h3-join"
}

/// Canvas multiple, frame step and frame offset: EmptyLTXVLatentVideo /32 & 8k+1, Wan /16 & 4k+1, H3 /32 & 17k+5.
fn grid(family: &str) -> (u64, u64, u64) {
    match family {
        "ltx-2" => (32, 8, 1),
        "wan" => (16, 4, 1),
        _ => (32, 17, 5),
    }
}

fn pick(o: &Value, key: &str, list: &[&str]) -> bool {
    o[key].as_str().is_some_and(|v| list.contains(&v))
}

pub(crate) fn continuity_id(s: &str) -> bool {
    !s.is_empty()
        && s.len() <= 80
        && s.bytes()
            .all(|b| b.is_ascii_alphanumeric() || b == b'-' || b == b'_')
}

fn keys_in(v: &Value, allowed: &[&str]) -> bool {
    v.as_object()
        .is_some_and(|o| o.keys().all(|k| allowed.contains(&k.as_str())))
}

pub(crate) fn valid_output(o: &Value) -> bool {
    keys_in(
        o,
        &[
            "codec",
            "container",
            "bitDepth",
            "quality",
            "audioCodec",
            "audioBitrate",
            "saveFirstFrame",
            "saveLastFrame",
            "imageFormat",
            "imageCompression",
        ],
    ) && pick(o, "codec", &CODECS)
        && pick(o, "container", &CONTAINERS)
        && pick(o, "bitDepth", &BIT_DEPTHS)
        && o["quality"].as_u64().is_some_and(|q| q <= 51)
        && pick(o, "audioCodec", &AUDIO_CODECS)
        && pick(o, "audioBitrate", &AUDIO_BITRATES)
        && o["saveFirstFrame"].is_boolean()
        && o["saveLastFrame"].is_boolean()
        && o.get("imageFormat")
            .is_none_or(|f| f.as_str().is_some_and(|f| ["png", "webp"].contains(&f)))
        && o.get("imageCompression")
            .is_none_or(|c| c.as_u64().is_some_and(|c| c <= 100))
}

fn finite(v: &Value, min: f64, max: f64) -> bool {
    v.as_f64()
        .is_some_and(|n| n.is_finite() && (min..=max).contains(&n))
}

pub(crate) fn learned_latent_model(name: &str) -> bool {
    comfy_model_name(name) && (name.ends_with(".safetensors") || name.ends_with(".sft"))
}

/// Post-upscale pixel canvas; H3 uses Python round's ties-to-even 32-pixel grid.
pub(crate) fn latent_upscale_size(i: &Value) -> (u64, u64) {
    let dimension = |key: &str| {
        let n = i[key].as_u64().unwrap_or(0);
        let Some(u) = i.get("latentUpscale") else {
            return n;
        };
        if i["family"] == "minimax-h3" {
            ((n as f64 * u["scale"].as_f64().unwrap_or(1.0) / 32.0).round_ties_even() as u64) * 32
        } else {
            n * 2
        }
    };
    (dimension("width"), dimension("height"))
}

pub(crate) fn h3_latent_model(name: &str) -> bool {
    let file = name
        .rsplit(['/', '\\'])
        .next()
        .unwrap_or_default()
        .to_ascii_lowercase();
    learned_latent_model(name)
        && file.starts_with("minimax_h3_latent_upscal")
        && !file.contains("ltx")
}

fn ltx_latent_model(name: &str) -> bool {
    let file = name
        .rsplit(['/', '\\'])
        .next()
        .unwrap_or_default()
        .to_ascii_lowercase();
    learned_latent_model(name)
        && file.starts_with("ltx")
        && file.contains("spatial")
        && file.contains("upscal")
}

/// Optional `DaSiWaH3TiledUpscale` inputs (intent key, node input); omitted keys keep the node defaults.
const H3_LATENT_ADVANCED_INPUTS: [(&str, &str); 14] = [
    ("cfg", "cfg"),
    ("scheduler", "scheduler"),
    ("precision", "upscale_precision"),
    ("memoryBudgetMb", "memory_budget_mb"),
    ("spatialTiling", "spatial_tiling"),
    ("temporalChunking", "temporal_chunking"),
    ("spikeGuard", "spike_guard"),
    ("guardSensitivity", "guard_sensitivity"),
    ("guardStrength", "guard_strength"),
    ("guardMode", "guard_mode"),
    ("memoryPlanning", "enforce_memory_budget"),
    ("memoryReservePct", "memory_reserve_pct"),
    ("continuitySoftRefine", "continuity_soft_refine"),
    ("continuityMaskStrength", "continuity_mask_strength"),
];

fn valid_h3_latent_advanced(a: &Value) -> bool {
    let Some(o) = a.as_object() else {
        return false;
    };
    o.iter().all(|(k, v)| match k.as_str() {
        "cfg" => finite(v, 0.0, 20.0),
        // Exact backend scheduler names are lowercase identifiers; the backend rejects unknown ones.
        "scheduler" => v.as_str().is_some_and(|s| {
            !s.is_empty()
                && s.len() <= 64
                && s.bytes()
                    .all(|b| b.is_ascii_lowercase() || b.is_ascii_digit() || b == b'_')
        }),
        "precision" => matches!(v.as_str(), Some("auto" | "bf16" | "fp16" | "fp32")),
        "memoryBudgetMb" => v.as_u64().is_some_and(|n| n <= 131_072),
        "spatialTiling"
        | "temporalChunking"
        | "spikeGuard"
        | "memoryPlanning"
        | "continuitySoftRefine" => v.is_boolean(),
        "guardSensitivity" => finite(v, 1.5, 12.0),
        "guardStrength" | "continuityMaskStrength" => finite(v, 0.0, 1.0),
        "guardMode" => matches!(v.as_str(), Some("burn_direction" | "both")),
        "memoryReservePct" => finite(v, 0.0, 100.0),
        _ => false,
    })
}

fn validate_latent_upscale(i: &Value, family: &str) -> Result<(), String> {
    let Some(u) = i.get("latentUpscale") else {
        return Ok(());
    };
    let settings = match family {
        "ltx-2" => keys_in(u, &["model", "scale"]) && u["scale"].as_f64() == Some(2.0),
        "minimax-h3" => {
            keys_in(u, &["model", "scale", "steps", "denoise", "advanced"])
                && finite(&u["scale"], 1.0, 8.0)
                && u["steps"].as_u64().is_some_and(|n| (1..=100).contains(&n))
                && finite(&u["denoise"], 0.0, 1.0)
                && u.get("advanced").is_none_or(valid_h3_latent_advanced)
        }
        _ => false,
    };
    if !settings
        || !u["model"].as_str().is_some_and(if family == "minimax-h3" {
            h3_latent_model
        } else {
            ltx_latent_model
        })
    {
        return Err("Invalid latentUpscale: learned .safetensors/.sft model and family-specific settings required".into());
    }
    let (w, h) = latent_upscale_size(i);
    if w > 8192 || h > 8192 || w * h > 16_777_216 {
        return Err("latentUpscale canvas exceeds dimension or pixel limits".into());
    }
    let prefix = format!("{}_original", effective_output_prefix(i).as_str().unwrap());
    if !safe_output_prefix(&prefix) {
        return Err("latentUpscale original output prefix exceeds limits".into());
    }
    if family == "minimax-h3"
        && i["h3"]["continuity"]["capture"] == true
        && i["h3"]["continuity"]["outputMode"] == "segment"
        && segment_crop_plan(i).is_none()
    {
        return Err("latentUpscale with captured segment output needs a pinned checkpoint clip (imported-video sources are unsupported) with its sourceFrames from the session list".into());
    }
    Ok(())
}

/// Compile-time copy of the node pack's segment_policy.render_layout crop fields: the core decode of
/// the prepared render window starts at the global frame offset, so the new segment is its final
/// extension frames. shortcut: mirrors the pack's layout constants; on pack drift the pack's own
/// render validation fails closed at runtime.
fn segment_crop_plan(i: &Value) -> Option<(u64, u64)> {
    let c = &i["h3"]["continuity"];
    if c["capture"] != true || c["outputMode"] != "segment" {
        return None;
    }
    // The node pack renders a segment crop only over a source window: a first take has none, and
    // an imported-video source builds its window latent inside SegmentPrepare (not reproducible
    // from compile-time fields), so only checkpoint pins are supported here.
    if c["sourceKind"] == "video" {
        return None;
    }
    let source = c["sourceFrames"].as_u64()?;
    // Continuation timing: newly visible seconds snapped to 17-frame steps. Without authored
    // duration the Director receives frames/24 seconds, so the snap runs on frames/17 directly.
    let extension = match c.get("durationSeconds").and_then(Value::as_f64) {
        Some(s) => ((s * 24.0 / 17.0 + 0.5).floor().max(1.0) as u64) * 17,
        None => ((i["frames"].as_f64()? / 17.0 + 0.5).floor().max(1.0) as u64) * 17,
    };
    Some((source - source.saturating_sub(102) / 51 * 51, extension))
}

/// prepare() must look up the pinned clip's frame count before compiling this intent.
pub(crate) fn needs_source_frames(i: &Value) -> bool {
    is_video(i)
        && i["family"] == "minimax-h3"
        && (i.get("latentUpscale").is_some() || i["videoPost"].get("derope").is_some())
        && i["h3"]["continuity"]["capture"] == true
        && i["h3"]["continuity"]["outputMode"] == "segment"
        && i["h3"]["continuity"]["sourceKind"] != "video"
        && i["h3"]["continuity"]["sourceId"]
            .as_str()
            .is_some_and(|s| !s.is_empty())
}

/// The pinned source's frame count from the read-only session clip list: the staged import for video
/// sources (matching canvas and mode family), otherwise the pinned checkpoint clip.
pub(crate) fn source_frames(list: &Value, i: &Value) -> Option<u64> {
    let c = &i["h3"]["continuity"];
    let id = c["sourceId"].as_str().filter(|s| !s.is_empty())?;
    let clip = list["clips"].as_array()?.iter().find(|cl| {
        if c["sourceKind"] == "video" {
            let p = &cl["importedVideo"];
            p["sourceId"] == id
                && p["width"] == i["width"]
                && p["height"] == i["height"]
                && p["modeFamily"]
                    == (if i["h3"]["mode"] == "REF2VA" {
                        "ref2va"
                    } else {
                        "fl2va"
                    })
        } else {
            cl["clipId"] == id
        }
    })?;
    clip["frames"].as_u64()
}

fn validate_ltx(l: &Value, frames: u64, source: bool) -> Result<(), String> {
    let passes = l["passes"].as_u64().unwrap_or(0);
    // Keyframes (multi-reference): an image at a pixel frame (-1 = last) with its guide strength.
    let keyframes_ok = l.get("keyframes").is_none_or(|k| {
        k.as_array().is_some_and(|a| {
            !a.is_empty()
                && a.len() <= 8
                && a.iter().all(|x| {
                    keys_in(x, &["image", "frame", "strength"])
                        && x["image"].as_str().is_some_and(model_name)
                        && x["frame"]
                            .as_i64()
                            .is_some_and(|f| f == -1 || (0..frames as i64).contains(&f))
                        && finite(&x["strength"], 0.0, 1.0)
                })
        })
    });
    if !keyframes_ok {
        return Err(
            "Invalid ltx.keyframes: 1-8 {image, frame 0..frames-1 or -1, strength 0-1}".into(),
        );
    }
    if source != l.get("sourceStrength").is_some()
        || l.get("sourceStrength")
            .is_some_and(|s| !finite(s, 0.0, 1.0))
    {
        return Err("ltx.sourceStrength (0-1) belongs exactly to a sourceVideo".into());
    }
    if keys_in(
        l,
        &[
            "textProjection",
            "audioVae",
            "passes",
            "spatialUpscaler",
            "keyframes",
            "sourceStrength",
        ],
    ) && ["textProjection", "audioVae"]
        .iter()
        .all(|k| l[*k].as_str().is_some_and(comfy_model_name))
        && (1..=3).contains(&passes)
        && (passes == 1) == l.get("spatialUpscaler").is_none()
        && l.get("spatialUpscaler")
            .is_none_or(|s| s.as_str().is_some_and(comfy_model_name))
    {
        Ok(())
    } else {
        Err("Invalid ltx: {textProjection, audioVae, passes 1-3, spatialUpscaler exactly when passes > 1}".into())
    }
}

fn validate_wan(w: &Value, steps: u64) -> Result<(), String> {
    if keys_in(w, &["lowModel", "shiftHigh", "shiftLow", "refinerStep"])
        && w["lowModel"].as_str().is_some_and(comfy_model_name)
        && finite(&w["shiftHigh"], 0.0, 100.0)
        && finite(&w["shiftLow"], 0.0, 100.0)
        && w["refinerStep"]
            .as_u64()
            .is_some_and(|r| r >= 1 && r < steps)
    {
        Ok(())
    } else {
        Err("Invalid wan: {lowModel, shiftHigh, shiftLow, refinerStep below steps}".into())
    }
}

fn validate_h3(h: &Value) -> Result<(), String> {
    let mode = h["mode"]
        .as_str()
        .filter(|m| H3_MODES.contains(m))
        .ok_or("Unsupported H3 mode (Image Inpaint is not a recipe yet)")?;
    let refs = h["references"].as_array().cloned().unwrap_or_default();
    if (mode == "REF2VA") != h.get("media").is_some() {
        return Err("h3.media belongs exactly to REF2VA".into());
    }
    let refmods = h.get("refmods").is_some();
    if refmods && mode != "REF2VA" {
        return Err("h3.refmods belong to REF2VA".into());
    }
    if refmods {
        validate_refmods(&h["refmods"])?;
    }
    if mode == "REF2VA" {
        let allow_empty = c_source(h) && h["continuity"]["useReferences"] != true;
        validate_h3_media(&h["media"], refmods, allow_empty)?;
    }
    let slots: Vec<u64> = refs.iter().filter_map(|r| r["slot"].as_u64()).collect();
    // Director slot semantics: I2VA = slot 0, L2VA = slot 1, FL2VA = {0,1}, T2VA = none.
    let slots_ok = refs.len() == slots.len()
        && refs.iter().all(|r| {
            r.as_object().is_some_and(|o| o.len() == 2)
                && r["image"]
                    .as_str()
                    .is_some_and(|s| s.starts_with("deas-inputs/") && model_name(s))
        })
        && match mode {
            "T2VA" | "REF2VA" => slots.is_empty(),
            "I2VA" => slots == [0],
            "L2VA" => slots == [1],
            _ => {
                !slots.is_empty()
                    && slots.len() <= 2
                    && slots.iter().all(|s| *s <= 1)
                    && slots.windows(2).all(|w| w[0] < w[1])
            }
        };
    let cont_ok = h.get("continuity").is_none_or(|c| {
        keys_in(
            c,
            &[
                "session",
                "sourceId",
                "sourceKind",
                "capture",
                "action",
                "outputMode",
                "overlapFrames",
                "useReferences",
                "durationSeconds",
                "sourceFrames",
            ],
        ) && c["session"]
            .as_str()
            .is_some_and(|s| continuity_id(s) && s != "_imports")
            && c["sourceId"]
                .as_str()
                .is_some_and(|s| s.is_empty() || continuity_id(s))
            && c.get("sourceKind").is_none_or(|kind| {
                kind == "video"
                    && c["sourceId"].as_str().is_some_and(|s| {
                        s.len() == 64
                            && s.bytes()
                                .all(|b| b.is_ascii_digit() || (b'a'..=b'f').contains(&b))
                    })
            })
            && c["capture"].is_boolean()
            && c.get("useReferences").is_none_or(Value::is_boolean)
            && c.get("durationSeconds").is_none_or(|seconds| {
                mode == "REF2VA"
                    && c_source(h)
                    && seconds
                        .as_f64()
                        .is_some_and(|s| s.is_finite() && s > 0.0 && s <= 15.0)
            })
            && c.get("sourceFrames")
                .is_none_or(|n| n.as_u64().is_some_and(|n| n >= 5 && (n - 5) % 17 == 0))
            && c["action"].as_str().is_some_and(|a| a.len() <= 50_000)
            && pick(c, "outputMode", &["full", "segment"])
            && c.get("overlapFrames")
                .is_none_or(|v| v.as_u64().is_some_and(|n| [73, 56, 39, 22, 5].contains(&n)))
    });
    if keys_in(
        h,
        &[
            "mode",
            "audioVae",
            "shiftVideo",
            "shiftAudio",
            "references",
            "continuity",
            "media",
            "inputScaling",
            "refmods",
        ],
    ) && h["audioVae"].as_str().is_some_and(comfy_model_name)
        && (h.get("inputScaling").is_none() || pick(h, "inputScaling", &H3_INPUT_SCALING))
        && finite(&h["shiftVideo"], 0.01, 100.0)
        && finite(&h["shiftAudio"], 0.01, 100.0)
        && slots_ok
        && cont_ok
    {
        Ok(())
    } else {
        Err("Invalid h3: {mode, audioVae, shiftVideo, shiftAudio, references[{slot, image in deas-inputs/}], continuity?, inputScaling?}".into())
    }
}

fn c_source(h: &Value) -> bool {
    h["continuity"]["sourceId"]
        .as_str()
        .is_some_and(|s| !s.is_empty())
}

/// REF2VA timeline media, mirroring the DaSiWa Director limits: ≤ 9 images, ≤ 3 videos, ≤ 3 audio, ≤ 12 files;
/// audio needs an image or video; unique slots per lane. Clip durations (2–15 s) are checked by the node.
/// Director RefMod rows (`_load_refmod_rows`): 1–8 unique slots 1–8, a library name, strength in (0, 1]
/// (the node skips 0), optional description. DEAS sends enabled rows only.
fn validate_refmods(r: &Value) -> Result<(), String> {
    let rows = r
        .as_array()
        .filter(|a| !a.is_empty() && a.len() <= 8)
        .ok_or("h3.refmods: 1-8 rows")?;
    let mut slots = vec![];
    for x in rows {
        let slot = x["slot"].as_u64().filter(|s| (1..=8).contains(s));
        let ok = keys_in(x, &["slot", "name", "strength", "description"])
            && slot.is_some_and(|s| !slots.contains(&s))
            && x["name"]
                .as_str()
                .is_some_and(|n| model_name(n) && n != "None" && n != "(none)")
            && x["strength"].as_f64().is_some_and(|s| s > 0.0 && s <= 1.0)
            && x.get("description")
                .is_none_or(|d| d.as_str().is_some_and(|d| d.chars().count() <= 2000));
        if !ok {
            return Err(
                "Invalid h3.refmods row: {slot 1-8 unique, name, strength (0, 1], description?}"
                    .into(),
            );
        }
        slots.extend(slot);
    }
    Ok(())
}

/// Empty media is valid with RefMods or a continuation that ignores references; present items still validate.
pub(crate) fn validate_h3_media(m: &Value, refmods: bool, allow_empty: bool) -> Result<(), String> {
    let items = m
        .as_array()
        .filter(|a| (allow_empty || refmods || !a.is_empty()) && a.len() <= 12)
        .ok_or("h3.media: 1-12 items")?;
    let mut used: Vec<(&str, u64)> = vec![];
    let (mut videos, mut audio, mut visual) = (0, 0, 0);
    let (mut video_seconds, mut audio_seconds) = (0.0, 0.0);
    for x in items {
        let kind = x["type"].as_str().unwrap_or_default();
        let mode = x.get("mediaMode").and_then(Value::as_str);
        let trims = ["trimStart", "trimEnd"]
            .iter()
            .all(|k| x.get(*k).is_none_or(|t| finite(t, 0.0, 3600.0)))
            && match (x["trimStart"].as_f64(), x["trimEnd"].as_f64()) {
                (Some(a), Some(b)) => a < b,
                _ => true,
            };
        let ok = keys_in(
            x,
            &["type", "file", "slot", "mediaMode", "trimStart", "trimEnd"],
        ) && x["file"].as_str().is_some_and(|f| {
            (f.starts_with("deas-inputs/") || f.starts_with("deas-input-")) && model_name(f)
        }) && match kind {
            "image" => mode.is_none() && x.get("trimStart").is_none() && x.get("trimEnd").is_none(),
            "video" => mode.is_none_or(|m| H3_MEDIA_MODES.contains(&m)) && trims,
            "audio" => mode.is_none() && trims,
            _ => false,
        };
        // A video used as sound only sits in the audio lane.
        let lane = if kind == "video" && mode == Some("audio") {
            "audio"
        } else {
            kind
        };
        let slot = x["slot"].as_u64();
        let max = H3_LANES
            .iter()
            .find(|(l, _)| *l == lane)
            .map_or(0, |(_, n)| *n);
        if !ok || !slot.is_some_and(|s| s < max) || used.contains(&(lane, slot.unwrap())) {
            return Err("Invalid h3.media item: {type image|video|audio, file in deas-inputs/, slot unique per lane, mediaMode? (video), trimStart/trimEnd? (video/audio)}".into());
        }
        used.push((lane, slot.unwrap()));
        if kind != "image" {
            if let Some(end) = x["trimEnd"].as_f64() {
                let seconds = end - x["trimStart"].as_f64().unwrap_or(0.0);
                if !(2.0..=15.0).contains(&seconds) {
                    return Err("REF2VA clips must last 2-15 seconds".into());
                }
                if kind == "video" && mode != Some("audio") {
                    video_seconds += seconds;
                }
                if kind == "audio" || mode == Some("audio") || mode == Some("video_audio") {
                    audio_seconds += seconds;
                }
            }
        }
        match (kind, mode) {
            ("image", _) => visual += 1,
            ("video", Some("audio")) => audio += 1,
            ("video", Some("video_audio")) => {
                videos += 1;
                audio += 1;
                visual += 1;
            }
            ("video", _) => {
                videos += 1;
                visual += 1;
            }
            _ => audio += 1,
        }
    }
    if visual + audio > 12 {
        return Err("REF2VA allows at most 12 references (video with sound counts twice)".into());
    }
    if video_seconds > 15.0 || audio_seconds > 15.0 {
        return Err("REF2VA video and audio totals must each be at most 15 seconds".into());
    }
    if videos > 3 || audio > 3 {
        return Err("REF2VA allows at most 3 videos and 3 audio clips".into());
    }
    if audio > 0 && visual == 0 && !refmods {
        return Err("REF2VA audio needs an image or video reference".into());
    }
    Ok(())
}

/// Family-specific block key.
pub(crate) fn block(family: &str) -> &'static str {
    match family {
        "ltx-2" => "ltx",
        "wan" => "wan",
        _ => "h3",
    }
}

/// Model-free Join clips prompt: validates the optional `h3.join` block against the
/// DaSiWaH3ClipAssemble contract (pinned by h3_join_contract_pins_pack_nodes_and_json_schema,
/// pack 0.5.42 assembly.py::_request; trims are seconds, effective cuts snap to 24-fps frames).
/// Chain ordering and export coverage are pack-verified at run time; DEAS does not duplicate that.
fn join(i: &Value) -> Result<Value, String> {
    if i["version"].as_f64() != Some(1.0) {
        return Err("Unsupported join recipe version".into());
    }
    if i.get("h3").is_some_and(|h| {
        h.as_object()
            .is_none_or(|o| o.keys().len() != 1 || !o.contains_key("join"))
    }) {
        return Err("h3 block must carry only the join block".into());
    }
    let j = &i["h3"]["join"];
    if j["kind"]
        .as_str()
        .is_none_or(|k| k != "segments" && k != "files")
    {
        return Err("h3.join.kind must be segments or files".into());
    }
    let rows: Vec<Value> = if j["kind"] == "segments" {
        let session = j["session"]
            .as_str()
            .filter(|s| continuity_id(s) && *s != "_imports")
            .ok_or("Invalid h3.join.session")?;
        let chain = j["chain"]
            .as_array()
            .filter(|a| !a.is_empty() && a.len() <= 100)
            .ok_or("h3.join.chain needs 1..=100 clip ids")?;
        chain
            .iter()
            .map(|c| {
                c.as_str()
                    .filter(|s| continuity_id(s))
                    .map(|clip| json!({"kind": "checkpoint", "session": session, "clip_id": clip}))
                    .ok_or("Invalid h3.join.chain entry".to_string())
            })
            .collect::<Result<_, _>>()?
    } else {
        let files = j["files"]
            .as_array()
            .filter(|a| !a.is_empty() && a.len() <= 100)
            .ok_or("h3.join.files needs 1..=100 entries")?;
        files
            .iter()
            .map(|f| -> Result<Value, String> {
                let name = f["filename"]
                    .as_str()
                    .filter(|s| {
                        !s.is_empty()
                            && s.len() <= 1024
                            && !s.contains("..")
                            && !s.contains('\0')
                            && !s.contains(':')
                            && !s.starts_with('/')
                    })
                    .ok_or("Invalid h3.join.files.filename")?;
                let seconds = |k: &str| -> Result<Option<f64>, String> {
                    match f.get(k) {
                        None | Some(Value::Null) => Ok(None),
                        Some(v) => v
                            .as_f64()
                            .filter(|n| (0.0..=3600.0).contains(n))
                            .map(Some)
                            .ok_or(format!("Invalid h3.join.files.{k}")),
                    }
                };
                let start = seconds("trimStart")?.unwrap_or_default();
                let end = seconds("trimEnd")?;
                if end.is_some_and(|e| e <= start) {
                    return Err("h3.join.files trim must end after its start".into());
                }
                Ok(json!({"kind": "media", "filename": name, "trim_start": start, "trim_end": end}))
            })
            .collect::<Result<_, _>>()?
    };
    if j.get("copyVideo").is_some_and(|b| !b.is_boolean()) {
        return Err("h3.join.copyVideo must be boolean".into());
    }
    let prefix = match j.get("filenamePrefix") {
        None | Some(Value::Null) => "H3_Joined".to_string(),
        Some(v) => v
            .as_str()
            .filter(|s| {
                !s.is_empty()
                    && s.len() <= 80
                    && s.bytes()
                        .all(|b| b.is_ascii_alphanumeric() || b == b'-' || b == b'_')
            })
            .map(str::to_string)
            .ok_or("Invalid h3.join.filenamePrefix")?,
    };
    let data = json!({
        "version": 1,
        "rows": rows,
        "repair_transitions": false,
        "copy_video": j["copyVideo"].as_bool().unwrap_or(false),
        "audio_policy": "preserve",
    });
    if data.to_string().len() > 65536 {
        return Err("h3.join request exceeds the pack's 64 KiB budget".into());
    }
    // Node "7" is the house saver-node id: native history output extraction reads only that node.
    Ok(
        json!({"7": {"class_type": "DaSiWaH3ClipAssemble", "inputs": {
            "assembly_data": data.to_string(),
            "filename_prefix": prefix,
        }}}),
    )
}

pub(crate) fn validate(i: &Value) -> Result<&str, String> {
    let object = i.as_object().ok_or("Expected a video intent object")?;
    let family = i["family"]
        .as_str()
        .filter(|f| FAMILIES.contains(f))
        .ok_or("Unknown video family")?;
    let block = block(family);
    if object
        .keys()
        .any(|k| !(FIELDS.contains(&k.as_str()) || OPTIONAL.contains(&k.as_str()) || k == block))
        || FIELDS.iter().any(|k| !object.contains_key(*k))
        || !object.contains_key(block)
    {
        return Err("Missing or unknown video intent fields".into());
    }
    if i["version"].as_f64() != Some(1.0) {
        return Err("Unsupported video recipe version".into());
    }
    for f in ["positivePrompt", "negativePrompt"] {
        if !i[f]
            .as_str()
            .is_some_and(|s| s.encode_utf16().count() <= 16384 && !s.contains('\0'))
        {
            return Err(format!("Invalid {f}"));
        }
    }
    if i.get("sourceVideo").is_some_and(|v| {
        // core LoadVideo lists top-level input files only.
        !v.as_str()
            .is_some_and(|s| model_name(s) && !s.contains('/'))
    }) || (i.get("sourceVideo").is_some() && family != "ltx-2")
    {
        return Err("sourceVideo: a top-level input video, LTX only".into());
    }
    for f in ["model", "textEncoder", "vae", "firstFrame", "lastFrame"] {
        if let Some(v) = i.get(f) {
            let valid = if ["model", "textEncoder", "vae"].contains(&f) {
                comfy_model_name
            } else {
                model_name
            };
            if !v.as_str().is_some_and(valid) {
                return Err(format!("Unsafe {f}"));
            }
        }
    }
    let (multiple, step, offset) = grid(family);
    let int = |k: &str, min: u64, max: u64| {
        i[k].as_u64()
            .filter(|n| (min..=max).contains(n))
            .ok_or(format!("Invalid {k}"))
    };
    let (w, h) = (int("width", 64, 8192)?, int("height", 64, 8192)?);
    let frames = int("frames", offset.max(1), 3600)?;
    if w % multiple != 0 || h % multiple != 0 || w * h > 16_777_216 || (frames - offset) % step != 0
    {
        return Err(format!(
            "Canvas must be a multiple of {multiple} and frames {step}k+{offset}"
        ));
    }
    int("seed", 0, 9_007_199_254_740_991)?;
    let steps = int("steps", 1, 150)?;
    if !finite(&i["frameRate"], 1.0, 120.0) || !finite(&i["cfg"], 0.0, 30.0) {
        return Err("Invalid frameRate or cfg".into());
    }
    if !["sampler", "scheduler"]
        .iter()
        .all(|f| i[*f].as_str().is_some_and(safe_choice))
    {
        return Err("Unsafe sampler or scheduler".into());
    }
    let vr = crate::model_families::video_recipe(family);
    if !vr.step_choices.is_empty() && !vr.step_choices.contains(&steps) {
        let allowed = vr
            .step_choices
            .iter()
            .map(|s| s.to_string())
            .collect::<Vec<_>>()
            .join("/");
        return Err(format!("Invalid steps: {family} only samples {allowed}"));
    }
    if vr
        .fixed_sampler
        .is_some_and(|s| i["sampler"].as_str() != Some(s))
    {
        return Err(format!(
            "Invalid sampler: {family} runs {} only",
            vr.fixed_sampler.unwrap()
        ));
    }
    if i.get("chunks")
        .is_some_and(|c| !c.as_u64().is_some_and(|n| (2..=16).contains(&n)))
    {
        return Err("Invalid chunks: 2..=16".into());
    }
    if i.get("output").is_some_and(|o| !valid_output(o)) {
        return Err("Invalid output settings".into());
    }
    if let Some(p) = i.get("videoPost") {
        crate::jobs_video_post::validate(p)?;
        if let Some(d) = p.get("derope") {
            // Prepare reads the latent the baseline frames were decoded from: one plain new take only.
            let c = &i["h3"]["continuity"];
            let segment_continuation =
                c["capture"] == true && c["outputMode"] == "segment" && c_source(&i["h3"]);
            if family != "minimax-h3" || (segment_continuation && segment_crop_plan(i).is_none()) {
                return Err("videoPost.derope runs on MiniMax H3; a new-segment continuation needs a pinned checkpoint clip (imported-video sources are unsupported) with its sourceFrames from the session list".into());
            }
            if let Some(lora) = d["lora"].as_str() {
                crate::jobs::validate_lora_format(lora)?;
                if crate::jobs::is_gguf(i["model"].as_str().unwrap_or_default()) {
                    return Err(
                        "MODEL_FORMAT_UNSUPPORTED: LoRA on a GGUF base is not proven".into(),
                    );
                }
            }
        }
    }
    if let Some(f) = i.get("faceRefine") {
        // With latent upscale + segment capture, latentUpscale's own validation requires the
        // checkpoint window that refinement then works on.
        if !is_h3(family) {
            return Err("faceRefine runs on MiniMax H3".into());
        }
        crate::jobs_face_refine::validate(f)?;
    }
    if i.get("loras").is_some_and(|l| {
        !l.as_array().is_some_and(|a| {
            a.len() <= 8
                && a.iter().all(|x| {
                    x.as_object().is_some_and(|o| o.len() == 2)
                        && x["name"].as_str().is_some_and(comfy_model_name)
                        && finite(&x["strength"], -10.0, 10.0)
                })
        })
    }) {
        return Err("Invalid loras".into());
    }
    if i.get("options").is_some_and(|o| !valid_options(o)) {
        return Err("Invalid options".into());
    }
    if i.get("outputPrefix")
        .is_some_and(|p| !p.as_str().is_some_and(safe_output_prefix))
    {
        return Err("Unsafe output prefix".into());
    }
    match family {
        "ltx-2" => validate_ltx(&i["ltx"], frames, i.get("sourceVideo").is_some())?,
        "wan" => validate_wan(&i["wan"], steps)?,
        _ => validate_h3(&i["h3"])?,
    }
    for name in [&i["vae"], &i["ltx"]["audioVae"], &i["h3"]["audioVae"]] {
        if crate::jobs::is_gguf(name.as_str().unwrap_or_default()) {
            return Err("MODEL_FORMAT_UNSUPPORTED: GGUF VAE is unsupported".into());
        }
    }
    if family == "minimax-h3-hyperflow"
        && !crate::jobs::is_gguf(i["model"].as_str().unwrap_or_default())
    {
        // The hub's INT8 convrot HyperFlow partition ships as diffusers shards for the Python
        // runtime; ComfyUI only ever sees the GGUF checkpoints.
        return Err(
            "MODEL_FORMAT_UNSUPPORTED: HyperFlow Flash checkpoints load in ComfyUI as GGUF only"
                .into(),
        );
    }
    // GGUF ref2va supports images only; mixed references require upstream's Python runtime.
    if family == "minimax-h3-hyperflow"
        && i["h3"]["media"]
            .as_array()
            .is_some_and(|items| items.iter().any(|item| item["type"] != "image"))
    {
        return Err("HyperFlow Flash GGUF accepts image references only".into());
    }
    if crate::jobs::is_gguf(i["ltx"]["textProjection"].as_str().unwrap_or_default()) {
        return Err("MODEL_FORMAT_UNSUPPORTED: GGUF text projection is unsupported".into());
    }
    if i.get("enhancedPreview").is_some() && !valid_preview(i) {
        return Err("Invalid enhancedPreview: incompatible decoder/model for video family".into());
    }
    validate_latent_upscale(i, family)?;
    for lora in i["loras"]
        .as_array()
        .into_iter()
        .flatten()
        .filter_map(|l| l["name"].as_str())
    {
        crate::jobs::validate_lora_format(lora)?;
    }
    // LoRA on a quantized base needs execution proof per pipeline; not advertised yet.
    if i["loras"].as_array().is_some_and(|l| !l.is_empty())
        && [&i["model"], &i["wan"]["lowModel"]]
            .iter()
            .any(|name| crate::jobs::is_gguf(name.as_str().unwrap_or_default()))
    {
        return Err("MODEL_FORMAT_UNSUPPORTED: LoRA on a GGUF base is not proven".into());
    }
    Ok(family)
}

/// Exact known decoder basenames only: unknown architectures must not become preview choices.
pub(crate) fn preview_model_compatible(family: &str, decoder: &str, model: &str) -> bool {
    if !comfy_model_name(model) {
        return false;
    }
    let file = model.rsplit(['/', '\\']).next().unwrap_or_default();
    matches!(
        (family, decoder, file),
        (
            "minimax-h3" | "minimax-h3-hyperflow",
            "tiny",
            "taeh3.safetensors"
        ) | ("ltx-2", "vae", "taeltx2_3.safetensors")
            | (
                "wan",
                "tiny",
                "taew2_1.safetensors" | "lighttaew2_1.safetensors"
            )
    )
}

fn valid_preview(i: &Value) -> bool {
    let p = &i["enhancedPreview"];
    p.as_object().is_some_and(|o| o.len() == 2)
        && preview_model_compatible(
            i["family"].as_str().unwrap_or_default(),
            p["decoder"].as_str().unwrap_or_default(),
            p["model"].as_str().unwrap_or_default(),
        )
}

/// Recheck the exact negotiated family/decoder/file before native admission, never downgrade.
pub(crate) fn validate_preview_capability(intent: &Value, allow: &Value) -> Result<(), String> {
    let Some(preview) = intent.get("enhancedPreview") else {
        return Ok(());
    };
    let family = intent["family"].as_str().unwrap_or_default();
    let has_node = |node: &str| {
        allow["nodes"]
            .as_array()
            .is_some_and(|n| n.iter().any(|n| n == node))
    };
    if !valid_preview(intent)
        || allow["videoPreviews"].get(family) != Some(preview)
        || !has_node("ModelPreviewOverrideKJ")
        || (preview["decoder"] == "vae"
            && (!has_node("VAELoader")
                || !allow["vaes"]
                    .as_array()
                    .is_some_and(|v| v.contains(&preview["model"]))))
    {
        return Err("enhancedPreview: exact compatible decoder capability is unavailable; refresh backend prerequisites".into());
    }
    Ok(())
}

pub(crate) fn compile(i: &Value) -> Result<Value, String> {
    if is_join(i) {
        return join(i);
    }
    if crate::jobs_face_refine::is_face_refine(i) {
        return crate::jobs_face_refine::compile(i);
    }
    if crate::jobs_video_post::is_enhance(i) {
        return crate::jobs_video_post::compile_enhance(i);
    }
    let mut graph = match validate(i)? {
        "ltx-2" => ltx(i),
        "wan" => wan(i)?,
        _ => h3(i),
    };
    if let Some(preview) = i.get("enhancedPreview") {
        // Patch each final sampling model, including Director output, split Wan and H3 upscale.
        let targets: Vec<(String, Value)> = graph
            .as_object()
            .unwrap()
            .iter()
            .filter(|(_, n)| {
                matches!(
                    n["class_type"].as_str(),
                    Some(
                        "BasicScheduler"
                            | "BasicGuider"
                            | "CFGGuider"
                            | "KSamplerAdvanced"
                            | "HyperFlowSigmas"
                            | "DaSiWaH3TiledUpscale"
                    )
                )
            })
            .map(|(id, n)| (id.clone(), n["inputs"]["model"].clone()))
            .collect();
        if preview["decoder"] == "vae" {
            graph["VPV"] = json!({"class_type":"VAELoader","inputs":{"vae_name":preview["model"]}});
        }
        let mut patched: Vec<(Value, String)> = Vec::new();
        for (target, model) in targets {
            let id = if let Some((_, id)) = patched.iter().find(|(source, _)| source == &model) {
                id.clone()
            } else {
                let id = format!("VP{}", patched.len() + 1);
                let mut inputs = json!({"model":model,"max_resolution":512,"jpeg_quality":80,"suppress_default_preview":false,"preview_frames":120,"preview_fps":8,"tiny_vae":"none"});
                if preview["decoder"] == "tiny" {
                    inputs["tiny_vae"] = preview["model"].clone();
                } else {
                    inputs["vae"] = json!(["VPV", 0]);
                }
                graph[&id] = json!({"class_type":"ModelPreviewOverrideKJ","inputs":inputs});
                patched.push((model, id.clone()));
                id
            };
            graph[&target]["inputs"]["model"] = json!([id, 0]);
        }
    }
    Ok(graph)
}

/// LoRAs, then the Options patches, then the family's feed-forward chunking; returns the final model link.
/// `clip` is `None` for model-only chains (Wan high/low, H3).
fn model_chain(
    g: &mut Value,
    prefix: &str,
    mut model: Value,
    mut clip: Option<&mut Value>,
    i: &Value,
    chunk_node: &str,
    threshold_key: &str,
) -> Value {
    for (n, lora) in i["loras"].as_array().into_iter().flatten().enumerate() {
        let id = format!("{prefix}L{}", n + 1);
        match clip.as_deref_mut() {
            Some(c) => {
                g[&id] = json!({"class_type":"LoraLoader","inputs":{"model":model,"clip":c.clone(),"lora_name":lora["name"],"strength_model":lora["strength"],"strength_clip":lora["strength"]}});
                *c = json!([id, 1]);
            }
            None => {
                g[&id] = json!({"class_type":"LoraLoaderModelOnly","inputs":{"model":model,"lora_name":lora["name"],"strength_model":lora["strength"]}})
            }
        }
        model = json!([id, 0]);
    }
    let o = &i["options"];
    let mut patch = |suffix: &str, node: &str, mut inputs: Value| {
        let id = format!("{prefix}{suffix}");
        inputs["model"] = model.clone();
        g[&id] = json!({"class_type":node,"inputs":inputs});
        model = json!([id, 0]);
    };
    if let Some(a) = o["attention"].as_str() {
        patch("A", "ModelAttentionBackend", json!({"attention":a}));
    }
    if let Some(s) = o["sage"].as_str() {
        patch("K", "PathchSageAttentionKJ", json!({"sage_attention":s}));
    }
    if let Some(c) = o.get("cache") {
        patch(
            "E",
            c["node"].as_str().unwrap(),
            json!({"reuse_threshold":c["threshold"],"start_percent":0.15,"end_percent":0.95,"verbose":false}),
        );
    }
    if let Some(n) = i["chunks"].as_u64() {
        // 4096 is the KJ default; the owner's workflows keep it.
        patch("H", chunk_node, json!({"chunks":n, threshold_key:4096}));
    }
    if let Some(b) = o["compile"].as_str() {
        patch("T", "TorchCompileModel", json!({"backend":b}));
    }
    model
}

/// Reference image → canvas (the workflows' TorchResize "Fill and crop" ≙ ImageScale crop=center).
fn input_image(g: &mut Value, id: &str, name: &Value, w: &Value, h: &Value) -> Value {
    g[id] = json!({"class_type":"LoadImage","inputs":{"image":name}});
    let scaled = format!("{id}S");
    g[&scaled] = json!({"class_type":"ImageScale","inputs":{"image":[id,0],"upscale_method":"lanczos","width":w,"height":h,"crop":"center"}});
    json!([scaled, 0])
}

fn decode(g: &mut Value, id: &str, samples: Value, vae: Value, i: &Value) {
    g[id] = match i["options"]["vaeTile"].as_u64() {
        Some(t) => {
            json!({"class_type":"VAEDecodeTiled","inputs":{"samples":samples,"vae":vae,"tile_size":t,"overlap":64,"temporal_size":64,"temporal_overlap":8}})
        }
        None => json!({"class_type":"VAEDecode","inputs":{"samples":samples,"vae":vae}}),
    };
}

/// Effective native combine settings, shared by execution and immutable history projection.
pub(crate) fn effective_output(i: &Value) -> Value {
    let mut output = json!({
        "codec":"Auto","container":"Auto","bitDepth":"Auto","quality":20,
        "audioCodec":"Auto","audioBitrate":"192k","saveFirstFrame":false,"saveLastFrame":false
    });
    if let Some(selected) = i["output"].as_object() {
        for (key, value) in selected {
            output[key] = value.clone();
        }
    }
    output
}

pub(crate) fn effective_output_prefix(i: &Value) -> Value {
    i.get("outputPrefix").cloned().unwrap_or_else(|| {
        json!(if crate::jobs_video_post::is_enhance(i) {
            "raw/tve/DEAS"
        } else {
            "raw/video/DEAS"
        })
    })
}

/// DaSiWa Enhanced Video Combine as node "7": the history reader looks there.
pub(crate) fn combine(
    g: &mut Value,
    images: Value,
    audio: Option<Value>,
    frame_rate: Value,
    i: &Value,
) {
    let o = effective_output(i);
    let mut inputs = json!({
        "images":images,"frame_rate":frame_rate,
        "codec":o["codec"],"container":o["container"],"bit_depth":o["bitDepth"],
        "quality":o["quality"],"log_level":"Standard","pingpong":false,"save_metadata":true,
        "filename_prefix":effective_output_prefix(i),"save_output":true,"pass_frames":false,"crop_to_audio":false,
        "audio_codec":o["audioCodec"],"audio_bitrate":o["audioBitrate"],
        "save_first_frame":o["saveFirstFrame"],"save_last_frame":o["saveLastFrame"],
        "seed":i["seed"]
    });
    if let Some(a) = audio {
        inputs["audio"] = a;
    }
    g["7"] = json!({"class_type":"DaSiWa_EnhancedVideoCombine","inputs":inputs});
}

/// Unprocessed baseline as "B7" at the pre-chain frame rate.
pub(crate) fn baseline_combine(
    g: &mut Value,
    images: Value,
    audio: Option<Value>,
    frame_rate: Value,
    i: &Value,
) {
    let mut saver = g["7"].clone();
    saver["inputs"]["images"] = images;
    match audio {
        Some(a) => saver["inputs"]["audio"] = a,
        None => {
            saver["inputs"].as_object_mut().unwrap().remove("audio");
        }
    }
    saver["inputs"]["frame_rate"] = frame_rate;
    saver["inputs"]["filename_prefix"] = json!(format!(
        "{}_original",
        effective_output_prefix(i).as_str().unwrap()
    ));
    g["B7"] = saver;
}

/// Optional TVE chain after the decode: returns (combine images, combine frame rate, combine audio).
fn post(
    g: &mut Value,
    images: Value,
    frame_rate: Value,
    audio: Option<Value>,
    i: &Value,
) -> (Value, Value, Option<Value>) {
    match i.get("videoPost") {
        Some(p) => {
            let looped = p.get("loop").is_some();
            let (images, audio) =
                crate::jobs_video_post::seamless_loop(g, images, frame_rate.clone(), audio, p);
            let out = crate::jobs_video_post::chain(g, images, p);
            // The whole chain (incl. its model loaders) sits behind the lazy input, so B7 (always
            // present with videoPost) is encoded before any post node starts.
            g["PG"] = json!({"class_type":"DEAS_VideoPostprocessGate","inputs":{"baseline":["B7",1],"image":out}});
            // Looped audio also passes the gate, else saver 7 would pull LP ahead of B7.
            let audio = match audio {
                Some(a) if looped => {
                    g["PG"]["inputs"]["audio"] = a;
                    Some(json!(["PG", 1]))
                }
                a => a,
            };
            let m = crate::jobs_video_post::multiplier(p);
            let fps = if m > 1 {
                json!(i["frameRate"].as_f64().unwrap() * m as f64)
            } else {
                frame_rate
            };
            (json!(["PG", 0]), fps, audio)
        }
        // A latent-upscale-only branch needs the same baseline-first lazy barrier.
        None if i.get("faceRefine").is_some() || i.get("latentUpscale").is_some() => {
            crate::jobs_face_refine::gate(g, images);
            (json!(["PG", 0]), frame_rate, audio)
        }
        None => (images, frame_rate, audio),
    }
}

/// The baseline is the first decode: before the latent upscale when there is one, else before the TVE chain.
fn needs_post_baseline(i: &Value) -> bool {
    (i.get("videoPost").is_some() || i.get("faceRefine").is_some())
        && i.get("latentUpscale").is_none()
}

/// One LTX sampling pass. `suffix` "" is the first pass; guides are re-added on the given video latent,
/// AV concat → SamplerCustomAdvanced → separate → crop guides. Returns (video latent link, audio latent link).
#[allow(clippy::too_many_arguments)]
fn ltx_pass(
    g: &mut Value,
    suffix: &str,
    video: Value,
    audio: Value,
    model: &Value,
    guides: &[(Value, i64, f64)],
    steps: Value,
    denoise: f64,
    i: &Value,
) -> (Value, Value) {
    let (mut cond, mut latent) = (json!(["CN"]), video);
    for (n, (image, idx, strength)) in guides.iter().enumerate() {
        let id = format!("G{}{suffix}", n + 1);
        g[&id] = json!({"class_type":"LTXVAddGuide","inputs":{"positive":[cond[0].clone(),0],"negative":[cond[0].clone(),1],"vae":["V",0],"latent":latent,"image":image,"frame_idx":idx,"strength":strength}});
        cond = json!([id]);
        latent = json!([id, 2]);
    }
    let (pos, neg) = (json!([cond[0].clone(), 0]), json!([cond[0].clone(), 1]));
    let (cat, z, gu, s, sep, cr) = (
        format!("CAT{suffix}"),
        format!("Z{suffix}"),
        format!("GU{suffix}"),
        format!("5{suffix}"),
        format!("SEP{suffix}"),
        format!("CR{suffix}"),
    );
    g[&cat] = json!({"class_type":"LTXVConcatAVLatent","inputs":{"video_latent":latent,"audio_latent":audio}});
    g[&z] = json!({"class_type":"BasicScheduler","inputs":{"model":model,"scheduler":i["scheduler"],"steps":steps,"denoise":denoise}});
    g[&gu] = json!({"class_type":"CFGGuider","inputs":{"model":model,"positive":pos,"negative":neg,"cfg":i["cfg"]}});
    g[&s] = json!({"class_type":"SamplerCustomAdvanced","inputs":{"noise":["N",0],"guider":[gu,0],"sampler":["Q",0],"sigmas":[z,0],"latent_image":[cat,0]}});
    g[&sep] = json!({"class_type":"LTXVSeparateAVLatent","inputs":{"av_latent":[s,0]}});
    let audio_out = json!([sep.clone(), 1]);
    if guides.is_empty() {
        return (json!([sep, 0]), audio_out);
    }
    g[&cr] = json!({"class_type":"LTXVCropGuides","inputs":{"positive":pos,"negative":neg,"latent":[sep,0]}});
    (json!([cr, 2]), audio_out)
}

fn ltx(i: &Value) -> Value {
    let l = &i["ltx"];
    let passes = l["passes"].as_u64().unwrap();
    let (w, h) = (i["width"].as_u64().unwrap(), i["height"].as_u64().unwrap());
    // Multipass samples the first pass at half canvas (OmniForge), then upsamples the latent 2×.
    let (w1, h1) = if passes > 1 { (w / 2, h / 2) } else { (w, h) };
    let mut g = json!({
        "1":unet_loader("ltx-2",&i["model"]),
        "C":crate::jobs::dual_clip_loader(&i["textEncoder"], &l["textProjection"], "ltxv"),
        "V":{"class_type":"VAELoader","inputs":{"vae_name":i["vae"]}},
        "AV":{"class_type":"VAELoader","inputs":{"vae_name":l["audioVae"]}},
        "N":{"class_type":"RandomNoise","inputs":{"noise_seed":i["seed"]}},
        "Q":{"class_type":"KSamplerSelect","inputs":{"sampler_name":i["sampler"]}},
        "EL":{"class_type":"EmptyLTXVLatentVideo","inputs":{"width":w1,"height":h1,"length":i["frames"],"batch_size":1}},
        "EA":{"class_type":"LTXVEmptyLatentAudio","inputs":{"frames_number":i["frames"],"frame_rate":i["frameRate"],"batch_size":1,"audio_vae":["AV",0]}},
    });
    let mut clip = json!(["C", 0]);
    let model = model_chain(
        &mut g,
        "",
        json!(["1", 0]),
        Some(&mut clip),
        i,
        "LTXVChunkFeedForward",
        "dim_threshold",
    );
    g["2"] =
        json!({"class_type":"CLIPTextEncode","inputs":{"text":i["positivePrompt"],"clip":clip}});
    g["3"] =
        json!({"class_type":"CLIPTextEncode","inputs":{"text":i["negativePrompt"],"clip":clip}});
    g["CN"] = json!({"class_type":"LTXVConditioning","inputs":{"positive":["2",0],"negative":["3",0],"frame_rate":i["frameRate"]}});
    // Guides the way the Director adds them, after LTXVPreprocess(img_compression 18): a source video as one
    // multi-frame guide at 0 (video-to-video), first frame at 0, keyframe images at their frame, last frame at -1.
    let mut sources: Vec<(String, Value, i64, f64)> = vec![];
    if let Some(video) = i.get("sourceVideo") {
        g["SV"] = json!({"class_type":"LoadVideo","inputs":{"file":video}});
        g["SVC"] = json!({"class_type":"GetVideoComponents","inputs":{"video":["SV",0]}});
        // shortcut: source frames are taken at the file's own rate (as the WhatDreamsCost Director does); resample when fps differ noticeably.
        g["SVT"] = json!({"class_type":"ImageFromBatch","inputs":{"image":["SVC",0],"batch_index":0,"length":i["frames"]}});
        g["SVS"] = json!({"class_type":"ImageScale","inputs":{"image":["SVT",0],"upscale_method":"lanczos","width":i["width"],"height":i["height"],"crop":"center"}});
        sources.push((
            "SV".into(),
            json!(["SVS", 0]),
            0,
            l["sourceStrength"].as_f64().unwrap(),
        ));
    }
    for (key, src, idx) in [("firstFrame", "8", 0i64), ("lastFrame", "9", -1)] {
        if let Some(name) = i.get(key) {
            let scaled = input_image(&mut g, src, name, &i["width"], &i["height"]);
            sources.push((src.into(), scaled, idx, 1.0));
        }
    }
    for (n, k) in l["keyframes"].as_array().into_iter().flatten().enumerate() {
        let src = format!("K{}", n + 1);
        let scaled = input_image(&mut g, &src, &k["image"], &i["width"], &i["height"]);
        sources.push((
            src,
            scaled,
            k["frame"].as_i64().unwrap(),
            k["strength"].as_f64().unwrap(),
        ));
    }
    let mut full = vec![];
    let mut half = vec![];
    for (src, scaled, idx, strength) in sources {
        g[&format!("{src}P")] =
            json!({"class_type":"LTXVPreprocess","inputs":{"image":scaled,"img_compression":18}});
        full.push((json!([format!("{src}P"), 0]), idx, strength));
        if passes > 1 {
            g[&format!("{src}H")] = json!({"class_type":"ImageScale","inputs":{"image":[format!("{src}P"),0],"upscale_method":"lanczos","width":w1,"height":h1,"crop":"disabled"}});
            half.push((json!([format!("{src}H"), 0]), idx, strength));
        }
    }
    let guides = if passes > 1 { &half } else { &full };
    let (mut video, mut audio) = ltx_pass(
        &mut g,
        "",
        json!(["EL", 0]),
        json!(["EA", 0]),
        &model,
        guides,
        i["steps"].clone(),
        1.0,
        i,
    );
    if passes > 1 {
        g["UL"] = json!({"class_type":"LatentUpscaleModelLoader","inputs":{"model_name":l["spatialUpscaler"]}});
        g["UP"] = json!({"class_type":"LTXVLatentUpsampler","inputs":{"samples":video,"upscale_model":["UL",0],"vae":["V",0]}});
        // OmniForge pass 2/3 steps and denoise.
        (video, audio) = ltx_pass(
            &mut g,
            "b",
            json!(["UP", 0]),
            audio,
            &model,
            &full,
            json!(4),
            0.4,
            i,
        );
        if passes == 3 {
            (video, audio) = ltx_pass(&mut g, "c", video, audio, &model, &full, json!(2), 0.2, i);
        }
    }
    if let Some(u) = i.get("latentUpscale") {
        decode(&mut g, "B6", video.clone(), json!(["V", 0]), i);
        g["UML"] =
            json!({"class_type":"LatentUpscaleModelLoader","inputs":{"model_name":u["model"]}});
        g["U"] = json!({"class_type":"LTXVLatentUpsampler","inputs":{"samples":video,"upscale_model":["UML",0],"vae":["V",0]}});
        video = json!(["U", 0]);
    }
    decode(&mut g, "6", video, json!(["V", 0]), i);
    g["AD"] =
        json!({"class_type":"LTXVAudioVAEDecode","inputs":{"samples":audio,"audio_vae":["AV",0]}});
    let (images, fps, audio) = post(
        &mut g,
        json!(["6", 0]),
        i["frameRate"].clone(),
        Some(json!(["AD", 0])),
        i,
    );
    combine(&mut g, images, audio, fps, i);
    if i.get("latentUpscale").is_some() {
        baseline_combine(
            &mut g,
            json!(["B6", 0]),
            Some(json!(["AD", 0])),
            i["frameRate"].clone(),
            i,
        );
    } else if needs_post_baseline(i) {
        baseline_combine(
            &mut g,
            json!(["6", 0]),
            Some(json!(["AD", 0])),
            i["frameRate"].clone(),
            i,
        );
    }
    g
}

fn wan(i: &Value) -> Result<Value, String> {
    let w = &i["wan"];
    if i.get("firstFrame").is_none() {
        return Err("Wan 2.2 image-to-video needs a first frame".into());
    }
    let mut g = json!({
        "1":unet_loader("wan",&i["model"]),
        "1L":unet_loader("wan",&w["lowModel"]),
        "C":crate::jobs::clip_loader(&i["textEncoder"], &json!("wan")),
        "V":{"class_type":"VAELoader","inputs":{"vae_name":i["vae"]}},
        "2":{"class_type":"CLIPTextEncode","inputs":{"text":i["positivePrompt"],"clip":["C",0]}},
        "3":{"class_type":"CLIPTextEncode","inputs":{"text":i["negativePrompt"],"clip":["C",0]}},
    });
    // shortcut: one LoRA list with one strength on both high and low; upgrade to per-model lists for split LoRAs (lightx2v).
    let high = model_chain(
        &mut g,
        "",
        json!(["1", 0]),
        None,
        i,
        "WanChunkFeedForward",
        "dim_threshold",
    );
    let low = model_chain(
        &mut g,
        "l",
        json!(["1L", 0]),
        None,
        i,
        "WanChunkFeedForward",
        "dim_threshold",
    );
    g["SH"] =
        json!({"class_type":"ModelSamplingSD3","inputs":{"model":high,"shift":w["shiftHigh"]}});
    g["SL"] = json!({"class_type":"ModelSamplingSD3","inputs":{"model":low,"shift":w["shiftLow"]}});
    let start = input_image(&mut g, "8", &i["firstFrame"], &i["width"], &i["height"]);
    let mut inputs = json!({"positive":["2",0],"negative":["3",0],"vae":["V",0],"width":i["width"],"height":i["height"],"length":i["frames"],"batch_size":1,"start_image":start});
    let node = match i.get("lastFrame") {
        Some(last) => {
            inputs["end_image"] = input_image(&mut g, "9", last, &i["width"], &i["height"]);
            "WanFirstLastFrameToVideo"
        }
        None => "WanImageToVideo",
    };
    g["W"] = json!({"class_type":node,"inputs":inputs});
    let sampler = |model: Value, latent: Value, first: bool| {
        json!({"class_type":"KSamplerAdvanced","inputs":{
            "model":model,"add_noise":if first {"enable"} else {"disable"},"noise_seed":i["seed"],"steps":i["steps"],"cfg":i["cfg"],
            "sampler_name":i["sampler"],"scheduler":i["scheduler"],"positive":["W",0],"negative":["W",1],"latent_image":latent,
            "start_at_step":if first {json!(0)} else {w["refinerStep"].clone()},"end_at_step":if first {w["refinerStep"].clone()} else {json!(10000)},
            "return_with_leftover_noise":if first {"enable"} else {"disable"}}})
    };
    g["KH"] = sampler(json!(["SH", 0]), json!(["W", 2]), true);
    g["KL"] = sampler(json!(["SL", 0]), json!(["KH", 0]), false);
    decode(&mut g, "6", json!(["KL", 0]), json!(["V", 0]), i);
    let (images, fps, audio) = post(&mut g, json!(["6", 0]), i["frameRate"].clone(), None, i);
    combine(&mut g, images, audio, fps, i);
    if needs_post_baseline(i) {
        baseline_combine(&mut g, json!(["6", 0]), None, i["frameRate"].clone(), i);
    }
    Ok(g)
}

/// H3 sigma schedule as `Z` (shifted `BasicScheduler`, or the distilled family's own sigma node
/// reading the stored schedule); returns the model link the guiders sample.
/// De-rope second pass (MAINodes Motion Lab via DaSiWa De-rope Prepare/Recover): hold the hot motion
/// spans of the baseline, re-render them at partial denoise, drop the holds; Prepare also moves the
/// Director's frame-indexed keyframes onto the slowed clock. Feeds the post gate, so
/// the baseline saver runs first; the result keeps the baseline audio (Motion Lab's reference_mix 1).
fn derope(g: &mut Value, images: Value, audio: Value, model: Value, d: &Value, i: &Value) -> Value {
    // A generation that already runs a distilled setup (turbo checkpoint or turbo LoRA, <= 8 steps)
    // gets Motion Lab's turbo schedule on its own model; a 25-step pass would over-resolve it.
    let distilled = i["steps"].as_u64().is_some_and(|s| s <= 8);
    let in_chain = |name: &Value| {
        i["loras"]
            .as_array()
            .is_some_and(|l| l.iter().any(|x| &x["name"] == name))
    };
    let (model, steps, scheduler) = match d.get("lora") {
        // Motion Lab's turbo pass: 6 total steps on beta, of which inject × 6 run. A LoRA the
        // generation chain already carries is not stacked a second time.
        Some(lora) if !in_chain(lora) => {
            g["DRL"] = json!({"class_type":"LoraLoaderModelOnly","inputs":{"model":model,"lora_name":lora,"strength_model":1.0}});
            (json!(["DRL", 0]), 6, json!("beta"))
        }
        Some(_) => (model, 6, json!("beta")),
        None if distilled => (model, 6, json!("beta")),
        None => (model, 25, i["scheduler"].clone()),
    };

    g["DRP"] = json!({"class_type":"DaSiWaH3DeropePrepare","inputs":{"images":images.clone(),"samples":["SP",0],"vae":["V",0],
        "preset":d["preset"],"frame_rate":i["frameRate"],"audio":audio,"audio_vae":["AV",0],"conditioning":["G",0],
        // A continuation's keyframes index the sampled clip, not the decoded timeline/window.
        "keep_keyframes":!c_source(&i["h3"])}});
    g["DRZ"] = json!({"class_type":"BasicScheduler","inputs":{"model":model,"scheduler":scheduler,"steps":steps,"denoise":1.0}});
    g["DRS"] = json!({"class_type":"SplitSigmasDenoise","inputs":{"sigmas":["DRZ",0],"denoise":d["inject"]}});
    g["DRG"] =
        json!({"class_type":"BasicGuider","inputs":{"model":model,"conditioning":["DRP",3]}});
    g["DRK"] = json!({"class_type":"SamplerCustomAdvanced","inputs":{"noise":["N",0],"guider":["DRG",0],"sampler":["Q",0],"sigmas":["DRS",1],"latent_image":["DRP",0]}});
    decode(g, "DRD", json!(["DRK", 0]), json!(["V", 0]), i);
    g["DRR"] = json!({"class_type":"DaSiWaH3DeropeRecover","inputs":{"images":["DRD",0],"hold_map":["DRP",1]}});
    if d["keepBackground"] == true {
        g["DRR"]["inputs"]["baseline"] = images;
        g["DRR"]["inputs"]["keep_background"] = json!(true);
    }
    json!(["DRR", 0])
}

pub(crate) fn h3_schedule(
    g: &mut Value,
    model: Value,
    family: &str,
    i: &Value,
    shift_video: &Value,
    shift_audio: &Value,
) -> Value {
    match crate::model_families::video_recipe(family).sigma_node {
        // Distilled checkpoints sample their own stored schedule: no shift or scheduler chain runs.
        Some(node) => {
            g["Z"] = json!({"class_type":node,"inputs":{"model":model.clone(),"steps":i["steps"]}});
            model
        }
        None => {
            g["SS"] = json!({"class_type":"MiniMaxH3SigmaShift","inputs":{"model":model,"shift_video":shift_video,"shift_audio":shift_audio}});
            g["Z"] = json!({"class_type":"BasicScheduler","inputs":{"model":["SS",0],"scheduler":i["scheduler"],"steps":i["steps"],"denoise":1.0}});
            json!(["SS", 0])
        }
    }
}

fn h3(i: &Value) -> Value {
    let h = &i["h3"];
    let mut items: Vec<Value> = h["references"]
        .as_array()
        .into_iter()
        .flatten()
        .enumerate()
        .map(|(n, r)| json!({"id":format!("ref{}",r["slot"]),"type":"image","value":r["image"],"slot":r["slot"],"order":n,"enabled":true}))
        .collect();
    // REF2VA timeline media (Director item contract: value = input-relative file, trims in seconds).
    for (n, m) in h["media"].as_array().into_iter().flatten().enumerate() {
        let mut item = json!({"id":format!("m{n}"),"type":m["type"],"value":m["file"],"slot":m["slot"],"order":n,"enabled":true});
        for (from, to) in [
            ("mediaMode", "media_mode"),
            ("trimStart", "trim_start"),
            ("trimEnd", "trim_end"),
        ] {
            if let Some(v) = m.get(from) {
                item[to] = v.clone();
            }
        }
        items.push(item);
    }
    // Director continuity contract (v3): an empty source_id is a new take; parse_settings fills the rest.
    let c = &h["continuity"];
    let mut continuity = if c_source(h) {
        let mut continuity = json!({"version":3,"session":c["session"],"capture":c["capture"],"output_mode":c["outputMode"],"continuation_prompt":c["action"]});
        if c["sourceKind"] == "video" {
            continuity["source_kind"] = json!("video");
            continuity["source_video_id"] = c["sourceId"].clone();
        } else {
            continuity["source_kind"] = json!("checkpoint");
            continuity["source_id"] = c["sourceId"].clone();
        }
        if let Some(frames) = c.get("overlapFrames") {
            continuity["overlap_frames"] = frames.clone();
        }
        continuity
    } else {
        json!({"version":3,"session":c.get("session").cloned().unwrap_or(json!("deas")),"capture":c.get("capture").cloned().unwrap_or(json!(false)),"output_mode":c.get("outputMode").cloned().unwrap_or(json!("full"))})
    };
    if let Some(use_references) = c.get("useReferences") {
        continuity["use_references"] = use_references.clone();
    }
    // DEAS already chose the canvas; by default the Director fills/crops the references to it.
    let scaling = h
        .get("inputScaling")
        .cloned()
        .unwrap_or(json!("Fill and crop"));
    let mut timeline = json!({"version":1,"items":items,"prompt_blocks":[],"resolution":{"input_scaling":scaling},"continuity":continuity});
    // RefMods (saved REF2VA references in models/refmods), loaded by the Director itself.
    if let Some(rows) = h["refmods"].as_array() {
        timeline["refmods"] = rows
            .iter()
            .map(|r| json!({"slot":r["slot"],"name":r["name"],"enabled":true,"strength":r["strength"],"description":r.get("description").cloned().unwrap_or(json!(""))}))
            .collect();
    }
    let mut g = json!({
        "1":unet_loader(i["family"].as_str().unwrap_or_default(),&i["model"]),
        "C":crate::jobs::clip_loader(&i["textEncoder"], &json!("minimax")),
        "V":{"class_type":"VAELoader","inputs":{"vae_name":i["vae"]}},
        "AV":{"class_type":"VAELoader","inputs":{"vae_name":h["audioVae"]}},
        "N":{"class_type":"RandomNoise","inputs":{"noise_seed":i["seed"]}},
        "Q":{"class_type":"KSamplerSelect","inputs":{"sampler_name":i["sampler"]}},
    });
    let model = model_chain(
        &mut g,
        "",
        json!(["1", 0]),
        None,
        i,
        "MiniMaxChunkFeedForward",
        "seq_threshold",
    );
    // REF2VA extensions need authored seconds, not a roundtrip through the new-take 17k+5 grid.
    g["D"] = json!({"class_type":"MiniMaxH3Director","inputs":{"mode":h["mode"],"prompt":i["positivePrompt"],"width":i["width"],"height":i["height"],
        "duration":c.get("durationSeconds").cloned().unwrap_or_else(|| json!(i["frames"].as_f64().unwrap() / 24.0)),"ref_image_size":"match","timeline_data":timeline.to_string(),"builder_state":"","frame_rate":i["frameRate"]}});
    // The Director pulls only the socket of its mode: ref2va_model for REF2VA, fl2va_model otherwise.
    g["D"]["inputs"][if h["mode"] == "REF2VA" {
        "ref2va_model"
    } else {
        "fl2va_model"
    }] = model;
    g["G"] = json!({"class_type":"MiniMaxH3DirectorGuide","inputs":{"clip":["C",0],"vae":["V",0],"guide":["D",0],"audio_vae":["AV",0]}});
    let sampling = h3_schedule(
        &mut g,
        json!(["D", 5]),
        i["family"].as_str().unwrap_or_default(),
        i,
        &h["shiftVideo"],
        &h["shiftAudio"],
    );
    g["B"] = json!({"class_type":"BasicGuider","inputs":{"model":sampling.clone(),"conditioning":["G",0]}});
    g["5"] = json!({"class_type":"SamplerCustomAdvanced","inputs":{"noise":["N",0],"guider":["B",0],"sampler":["Q",0],"sigmas":["Z",0],"latent_image":["G",1]}});
    // Segment Prepare/Decode serve both Director output modes and are plain decode without capture.
    g["SP"] = json!({"class_type":"DaSiWaH3ContinuitySegmentPrepare","inputs":{"sampled":["5",0],"context":["G",2]}});
    g["SD"] = json!({"class_type":"DaSiWaH3ContinuitySegmentDecode","inputs":{"latent":["SP",0],"vae":["V",0],"audio_vae":["AV",0],"context":["SP",1]}});
    let upscale = i.get("latentUpscale").is_some();
    let segment_capture = c["capture"] == true && c["outputMode"] == "segment";
    let derope_block = i["videoPost"].get("derope");
    let refining = derope_block.is_some() || i.get("faceRefine").is_some();
    // A continued new-segment capture decodes only the new segment from a render window that also
    // holds the source tail: De-rope (and a re-encode for the upscale) needs the whole window.
    let window =
        segment_capture && c_source(h) && (derope_block.is_some() || (upscale && refining));
    let (mut frames, mut audio) = if window {
        decode(&mut g, "BA", json!(["SP", 0]), json!(["V", 0]), i);
        g["WA"] =
            json!({"class_type":"VAEDecodeAudio","inputs":{"samples":["SP",0],"vae":["AV",0]}});
        (json!(["BA", 0]), json!(["WA", 0]))
    } else if upscale && !segment_capture {
        // With latent upscale, the fixes work on the base decode BSD (SD decodes the upscale).
        g["BSD"] = g["SD"].clone();
        (json!(["BSD", 0]), json!(["BSD", 1]))
    } else {
        (json!(["SD", 0]), json!(["SD", 1]))
    };
    // De-rope re-renders the whole clip, so it runs before face refinement and the TVE chain.
    if let Some(d) = derope_block {
        frames = derope(&mut g, frames, audio.clone(), sampling.clone(), d, i);
    }
    if window && !upscale {
        // Back to the new segment before face refinement; the segment decode carries its audio.
        let (start, count) = segment_crop_plan(i).expect("validated with videoPost.derope");
        g["WC"] = json!({"class_type":"ImageFromBatch","inputs":{"image":frames,"batch_index":start,"length":count}});
        frames = json!(["WC", 0]);
        audio = json!(["SD", 1]);
    }
    if let Some(f) = i.get("faceRefine") {
        frames = crate::jobs_face_refine::insert(
            &mut g,
            frames,
            Some(audio),
            json!(["D", 8]),
            sampling,
            f,
        );
    }
    if upscale && refining {
        // Fix first, then upscale: re-encode the refined frames beside the untouched audio latent.
        g["RS"] = json!({"class_type":"LTXVSeparateAVLatent","inputs":{"av_latent":["SP",0]}});
        g["RE"] =
            json!({"class_type":"VAEEncode","inputs":{"pixels":frames.clone(),"vae":["V",0]}});
        g["RC"] = json!({"class_type":"LTXVConcatAVLatent","inputs":{"video_latent":["RE",0],"audio_latent":["RS",1]}});
    }
    // With latent upscale the post chain starts at its decode (core crop CB for segment capture).
    let decoded = if upscale && segment_capture {
        json!(["CB", 0])
    } else if upscale {
        json!(["SD", 0])
    } else {
        frames
    };

    let (images, fps, audio) = post(&mut g, decoded, json!(["D", 8]), Some(json!(["SD", 1])), i);
    // With latent upscale the saver's audio comes from the upscale decode: pass it through the gate
    // too, else saver 7 pulls the upscale (and everything before it) ahead of the baseline B7.
    let audio = match audio {
        Some(a) if upscale && !segment_capture && g["PG"]["inputs"].get("audio").is_none() => {
            g["PG"]["inputs"]["audio"] = a;
            Some(json!(["PG", 1]))
        }
        a => a,
    };
    combine(&mut g, images, audio, fps, i);
    if needs_post_baseline(i) {
        baseline_combine(
            &mut g,
            json!(["SD", 0]),
            Some(json!(["SD", 1])),
            json!(["D", 8]),
            i,
        );
    }
    if let Some(u) = i.get("latentUpscale") {
        // Segment capture keeps its only SegmentDecode on SP for exact, pre-upscale audio cropping;
        // the pack requires that audio directly on exporter 7. Core nodes decode/crop Processed.
        g["U"] = json!({"class_type":"DaSiWaH3TiledUpscale","inputs":{
            "model":["SS",0],"conditioning":["G",0],"latent":if refining {json!(["RC",0])} else {json!(["SP",0])},"continuity_context":["SP",1],
            "director_guide":["D",0],"vae":["V",0],"sampler":["Q",0],"noise":["N",0],"sampler_name":i["sampler"],
            "scale":u["scale"],"upscale_model":u["model"],"steps":u["steps"],"denoise":u["denoise"],"seed":i["seed"],
            "cfg":1.0,"scheduler":"simple","memory_budget_mb":0,"upscale_precision":"auto",
            "continuity_soft_refine":false,"continuity_mask_strength":1.0,
            "spatial_tiling":true,"temporal_chunking":true,"spike_guard":false,
            "guard_sensitivity":4.3,"guard_strength":1.0,"guard_mode":"burn_direction",
            "enforce_memory_budget":true,"memory_reserve_pct":5.0
        }});
        if let Some(a) = u.get("advanced") {
            for (key, input) in H3_LATENT_ADVANCED_INPUTS {
                if let Some(v) = a.get(key) {
                    g["U"]["inputs"][input] = v.clone();
                }
            }
        }
        if segment_capture {
            // The render plan is derived at runtime from the prepared latent tensor and context;
            // SegmentDecode accepts no duration input. The compile-time crop mirrors the pack's
            // continuation timing for the duration the Director received (durationSeconds else frames/24).
            let (crop_start, crop_frames) =
                segment_crop_plan(i).expect("validated in validate_latent_upscale");
            decode(&mut g, "UD", json!(["U", 0]), json!(["V", 0]), i);
            g["CB"] = json!({"class_type":"ImageFromBatch","inputs":{"image":["UD",0],"batch_index":crop_start,"length":crop_frames}});
            baseline_combine(
                &mut g,
                json!(["SD", 0]),
                Some(json!(["SD", 1])),
                json!(["D", 8]),
                i,
            );
        } else {
            g["SD"]["inputs"]["latent"] = json!(["U", 0]);
            baseline_combine(
                &mut g,
                json!(["BSD", 0]),
                Some(json!(["BSD", 1])),
                json!(["D", 8]),
                i,
            );
        }
    }
    g["P"] = json!({"class_type":"DaSiWaH3ContinuityPublish","inputs":{"filename":["7",1],"ticket":["SP",2]}});
    g
}

fn strs<'a>(v: &[&'a Value]) -> Vec<&'a str> {
    v.iter().filter_map(|x| x.as_str()).collect()
}

/// GGUF files load through the family's declared GGUF node (HyperFlow GGUFs need their own
/// loader; they carry no `general.architecture`), which takes no weight_dtype.
pub(crate) fn unet_loader(family: &str, name: &Value) -> Value {
    if crate::jobs::is_gguf(name.as_str().unwrap_or_default()) {
        json!({"class_type":crate::model_families::video_recipe(family).gguf_loader,"inputs":{"unet_name":name}})
    } else {
        json!({"class_type":"UNETLoader","inputs":{"unet_name":name,"weight_dtype":"default"}})
    }
}

/// Model/encoder/VAE/image/upscaler names prepare() must find in object_info, per allowlist field.
pub(crate) fn requirements(i: &Value) -> Vec<(&'static str, Vec<&str>)> {
    if is_join(i) {
        // Model-free assembly: the pack nodes ride H3_CONTINUITY_NODES evidence; no models/files needed.
        return Vec::new();
    }
    if crate::jobs_face_refine::is_face_refine(i) {
        return crate::jobs_face_refine::requirements(i);
    }
    if crate::jobs_video_post::is_enhance(i) {
        return crate::jobs_video_post::requirements(&i["videoPost"]);
    }
    let family = i["family"].as_str().unwrap_or_default();
    let b = &i[block(family)];
    let (gguf, plain): (Vec<&str>, Vec<&str>) = strs(&[&i["model"], &b["lowModel"]])
        .into_iter()
        .partition(|name| crate::jobs::is_gguf(name));
    let quantized_clip = crate::jobs::is_gguf(i["textEncoder"].as_str().unwrap_or_default());
    let (encoders, types) = match (quantized_clip, family == "ltx-2") {
        (true, true) => ("ggufDualTextEncoders", "ggufDualClipTypes"),
        (true, false) => ("ggufTextEncoders", "ggufClipTypes"),
        _ => ("textEncoders", "clipTypes"),
    };
    let mut required = vec![
        ("diffusionModels", plain),
        ("ggufDiffusionModels", gguf),
        (encoders, strs(&[&i["textEncoder"], &b["textProjection"]])),
        ("vaes", strs(&[&i["vae"], &b["audioVae"]])),
        (
            types,
            vec![match family {
                "ltx-2" => "ltxv",
                "wan" => "wan",
                _ => "minimax",
            }],
        ),
        (
            "images",
            // object_info lists only the input folder; ComfyUI resolves `[output]` files itself.
            strs(&[&i["firstFrame"], &i["lastFrame"]])
                .into_iter()
                .chain(
                    b["references"]
                        .as_array()
                        .into_iter()
                        .flatten()
                        .filter_map(|r| r["image"].as_str()),
                )
                .chain(
                    b["keyframes"]
                        .as_array()
                        .into_iter()
                        .flatten()
                        .filter_map(|k| k["image"].as_str()),
                )
                .chain(
                    b["media"]
                        .as_array()
                        .into_iter()
                        .flatten()
                        .filter(|m| {
                            m["type"] == "image"
                                && !(is_h3(family)
                                    && b["mode"] == "REF2VA"
                                    && c_source(b)
                                    && b["continuity"]["useReferences"] != true)
                        })
                        .filter_map(|m| m["file"].as_str()),
                )
                .filter(|s| !s.ends_with(" [output]"))
                .collect(),
        ),
        (
            "h3LatentUpscaleModels",
            (family == "minimax-h3")
                .then(|| i["latentUpscale"]["model"].as_str())
                .flatten()
                .into_iter()
                .collect(),
        ),
        (
            "latentUpscaleModels",
            strs(&[&b["spatialUpscaler"]])
                .into_iter()
                .chain(
                    (family == "ltx-2")
                        .then(|| i["latentUpscale"]["model"].as_str())
                        .flatten(),
                )
                .collect(),
        ),
    ];
    if i["enhancedPreview"]["decoder"] == "vae" {
        required.push(("vaes", strs(&[&i["enhancedPreview"]["model"]])));
    }
    required.extend(crate::jobs_video_post::requirements(&i["videoPost"]));
    if let Some(sam) = i["faceRefine"]["samCheckpoint"].as_str() {
        required.push(("checkpoints", vec![sam]));
    }
    required
}

#[cfg(test)]
#[path = "jobs_video_tests.rs"]
pub(crate) mod tests;
