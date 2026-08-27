use comfy_model::{
    ArtifactIndex, ArtifactKey, ArtifactRoot, CosmosArchitecture, CosmosModelSize, CosmosRatio,
    ModelClipConfigurationFact, ModelClipModelInvocation, ModelFamilyDefinition, ModelFamilyError,
    ModelFamilyRegistration, ModelFamilyRegistry, ModelParsedFacts, ModelParsedFormatFact,
    ModelParsedTensorFact, ModelProbe, ModelStateTransaction, ModelStore, NativeFamilyBuildOptions,
    ParserLimits, PatchApplication, PatchGraph, PatchKind, PatchOperation, PatchTarget,
    build_model_family_for_probe, describe_model_family,
    generated_cosmosi2vpredict2_comfy_model_0072 as cosmos,
};
use comfy_tensor::{
    CpuBackend, CpuWorkspaceAuthority, DType, ExecutionContext, StreamId, Tensor, TensorBackend,
    generated_comfy_operator_indirection_01::{
        tensor_from_f32_with_context_exact_native, tensor_to_f32_with_context_exact_native,
    },
};
use comfy_types::{CancellationToken, DeviceKind};
use sha2::{Digest, Sha256};
use std::{collections::BTreeMap, io::Write, path::Path};

const ARTIFACT_DIGEST: &str = "0720720720720720720720720720720720720720720720720720720720720720";
const RESOLVED_MEMORY_BYTES: u64 = 147_476;

static AMBIGUOUS_FAMILY: ModelFamilyDefinition = ModelFamilyDefinition {
    feature_id: "COMFY-MODEL-9072",
    identifier: "CosmosI2VPredict2AmbiguousFixture",
    ..cosmos::MODEL_FAMILY
};

static AMBIGUOUS_REGISTRATIONS: [ModelFamilyRegistration; 2] = [
    cosmos::MODEL_FAMILY_REGISTRATION,
    ModelFamilyRegistration {
        definition: &AMBIGUOUS_FAMILY,
        source_ordinal: 144,
        source_architecture: "model_base.CosmosPredict2AmbiguousFixture",
        ..cosmos::MODEL_FAMILY_REGISTRATION
    },
];

#[test]
fn val_model_family_row_001_cosmosi2vpredict2_source_profiles_and_ownership()
-> Result<(), Box<dyn std::error::Error>> {
    assert_eq!(cosmos::MODEL_FAMILY_IDENTIFIER, "CosmosI2VPredict2");
    assert_eq!(cosmos::MODEL_FAMILY_FEATURE_ID, "COMFY-MODEL-0072");
    assert_eq!(
        cosmos::MODEL_FAMILY_FIXTURE,
        "cosmosi2vpredict2-comfy-model-0072"
    );
    assert_eq!(cosmos::MODEL_FAMILY_SOURCE_ORDINAL, 44);
    assert_eq!(cosmos::MODEL_FAMILY_REGISTRATION.source_ordinal, 44);
    assert_eq!(
        cosmos::MODEL_FAMILY_REGISTRATION.source_architecture,
        "model_base.CosmosPredict2(image_to_video=True)"
    );
    assert!(cosmos::MODEL_FAMILY_REGISTRATION.source_configuration.is_empty());
    assert_eq!(cosmos::MODEL_FAMILY_MEMORY_USAGE_FACTOR, 1.0);
    assert_eq!(cosmos::MODEL_FAMILY_TWO_B_MEMORY_USAGE_FACTOR, 0.95);
    assert_eq!(cosmos::MODEL_FAMILY_FOURTEEN_B_MEMORY_USAGE_FACTOR, 2.375);
    assert_eq!(cosmos::MODEL_FAMILY_SIGMA_DATA, 1.0);
    assert_eq!(cosmos::MODEL_FAMILY_SIGMA_MAX, 80.0);
    assert_eq!(cosmos::MODEL_FAMILY_SIGMA_MIN, 0.002);

    let descriptor = describe_model_family(&cosmos::MODEL_FAMILY)?;
    assert_eq!(descriptor.identifier, "CosmosI2VPredict2");
    assert_eq!(descriptor.family, "COMFY-MODEL-0072");
    assert_eq!(descriptor.architecture_version, "cosmos-predict2-i2v-v1");
    assert_eq!(descriptor.latent_format, "Wan21");
    assert_eq!(
        descriptor.supported_dtypes,
        ["bfloat16", "float16", "float32"]
    );
    assert_eq!(descriptor.supported_devices, [DeviceKind::Cpu]);
    assert_eq!(descriptor.component_graph.len(), 3);

    let two_b =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 17, 2_048, false, false, "native"))?;
    let configuration = cosmos::configuration_for_probe(&two_b)?;
    assert_eq!(configuration.architecture, CosmosArchitecture::Predict2);
    assert_eq!(configuration.in_channels, 17);
    assert_eq!(configuration.out_channels, 16);
    assert_eq!(configuration.model_channels, 2_048);
    assert_eq!(configuration.number_of_blocks, 28);
    assert_eq!(configuration.number_of_heads, 16);
    assert_eq!(configuration.maximum_image_height, 240);
    assert_eq!(configuration.maximum_image_width, 240);
    assert_eq!(configuration.maximum_frames, 128);
    assert_eq!(configuration.spatial_patch_size, 2);
    assert_eq!(configuration.temporal_patch_size, 1);
    assert!(configuration.concatenate_padding_mask);
    assert!(configuration.image_to_video);
    assert!(configuration.positional_embeddings_learnable);
    assert_eq!(configuration.model_size, CosmosModelSize::Predict2TwoB);
    assert_eq!(
        configuration.rope_extrapolation,
        [ratio(3, 1), ratio(3, 1), ratio(1, 1)]
    );
    assert_eq!(configuration.extra_extrapolation, Some([ratio(1, 1); 3]));
    assert_eq!(configuration.extra_per_block_absolute_position, Some(false));
    assert_eq!(
        configuration.cross_attention_embedding_channels,
        Some(1_024)
    );
    assert_eq!(configuration.minimum_frames_per_second, Some(1));
    assert_eq!(configuration.maximum_frames_per_second, Some(30));
    assert_eq!(configuration.adaln_lora_dimension, 256);
    assert_eq!(configuration.memory_usage_factor, 0.95);

    let fourteen_b =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 17, 5_120, false, false, "native"))?;
    let configuration = cosmos::configuration_for_probe(&fourteen_b)?;
    assert_eq!(configuration.model_size, CosmosModelSize::FourteenB);
    assert_eq!(
        (
            configuration.number_of_blocks,
            configuration.number_of_heads
        ),
        (36, 40)
    );
    assert_eq!(
        configuration.rope_extrapolation,
        [ratio(2, 1), ratio(2, 1), ratio(5, 6)]
    );
    assert_eq!(configuration.extra_per_block_absolute_position, None);
    assert_eq!(configuration.memory_usage_factor, 2.375);
    let registry =
        ModelFamilyRegistry::checked_registrations(&[cosmos::MODEL_FAMILY_REGISTRATION])?;
    let resolved = registry.resolve(&fourteen_b)?;
    assert_eq!(resolved.profile().memory_estimator.bytes_per_parameter, 3);

    let mut misleading_facts = parsed_facts(DType::F32, 17, 2_048, false, false, "native");
    misleading_facts.formats[0].metadata.extend([
        ("image_model".to_owned(), "cosmos".to_owned()),
        ("in_channels".to_owned(), "16".to_owned()),
        ("model_layout".to_owned(), "diffusers".to_owned()),
    ]);
    let misleading = ModelProbe::from_parsed_facts(misleading_facts)?;
    let misleading_resolved = registry.resolve(&misleading)?;
    assert_eq!(
        misleading_resolved.detection().identity.feature_id(),
        cosmos::MODEL_FAMILY_FEATURE_ID
    );
    let misleading_configuration = cosmos::configuration_for_probe(&misleading)?;
    assert_eq!(misleading_configuration.architecture, CosmosArchitecture::Predict2);
    assert_eq!(misleading_configuration.in_channels, 17);
    assert!(misleading_configuration.image_to_video);

    let repository = Path::new(env!("CARGO_MANIFEST_DIR")).join("../..");
    assert_eq!(
        sha256(&std::fs::read(
            repository.join(cosmos::MODEL_FAMILY_SOURCE_PATH)
        )?),
        cosmos::MODEL_FAMILY_SOURCE_SHA256
    );
    let provenance: serde_json::Value =
        serde_json::from_slice(&std::fs::read(fixture_directory().join("provenance.json"))?)?;
    assert_eq!(provenance["feature_id"], cosmos::MODEL_FAMILY_FEATURE_ID);
    assert_eq!(provenance["source_symbol"], cosmos::MODEL_FAMILY_IDENTIFIER);
    assert_eq!(provenance["source_ordinal"], 44);
    let projection = provenance["source_projection"]
        .as_str()
        .ok_or("CosmosI2VPredict2 source projection must be a string")?;
    assert_eq!(
        sha256(projection.as_bytes()),
        provenance["source_projection_sha256"]
    );
    for source in provenance["source_files"]
        .as_array()
        .ok_or("CosmosI2VPredict2 source_files must be an array")?
    {
        let path = source["path"]
            .as_str()
            .ok_or("source path must be a string")?;
        let expected = source["sha256"]
            .as_str()
            .ok_or("source digest must be a string")?;
        assert_eq!(sha256(&std::fs::read(repository.join(path))?), expected);
    }

    let catalog: serde_json::Value = serde_json::from_slice(&std::fs::read(
        Path::new(env!("CARGO_MANIFEST_DIR")).join("catalog/model-families-v1.json"),
    )?)?;
    let row = catalog["models"]
        .as_array()
        .ok_or("model catalog must contain models")?
        .iter()
        .find(|row| row["feature_id"] == cosmos::MODEL_FAMILY_FEATURE_ID)
        .ok_or("CosmosI2VPredict2 catalog row is missing")?;
    assert_eq!(row["source_ordinal"], 44);
    assert_eq!(row["static"]["unet_config"]["value"]["in_channels"], 17);
    assert_eq!(
        sha256(&serde_json::to_vec(row)?),
        cosmos::MODEL_FAMILY_PROJECTION_SHA256
    );
    assert_eq!(
        provenance["catalog_projection_sha256"],
        cosmos::MODEL_FAMILY_PROJECTION_SHA256
    );

    let row_source = std::fs::read_to_string(
        Path::new(env!("CARGO_MANIFEST_DIR"))
            .join("src/families/cosmosi2vpredict2_comfy_model_0072.rs"),
    )?;
    for duplicate_owner in [
        "pub struct CosmosI2VPredict2Configuration",
        "pub enum CosmosI2VPredict2ModelSize",
        "fn shape(",
        "struct CancellationToken",
        "struct Tensor",
        "struct ModelStore",
        "struct ModelProbe",
        "struct ModelStateTransaction",
        "struct PatchGraph",
        "struct CpuWorkspaceAuthority",
        "std::fs",
        "unsafe ",
    ] {
        assert!(!row_source.contains(duplicate_owner));
    }
    assert!(row_source.contains("cosmos_configuration_for_probe("));
    assert!(!row_source.contains("ModelDetectionRule::Metadata"));
    assert!(!row_source.contains("ModelSourceConfigurationRule"));
    assert!(row_source.contains("ModelDetectionRule::AnyKeyPresent"));
    assert!(row_source.contains("ModelDetectionRule::AnyTensorDimensionValue"));
    assert!(row_source.contains("source_configuration: &[]"));
    let owner_source = std::fs::read_to_string(
        Path::new(env!("CARGO_MANIFEST_DIR")).join("src/cosmos_family.rs"),
    )?;
    assert_eq!(
        owner_source
            .matches("pub struct CosmosConfiguration")
            .count(),
        1
    );
    assert_eq!(
        owner_source.matches("pub enum CosmosArchitecture").count(),
        1
    );
    assert_eq!(owner_source.matches("pub enum CosmosModelSize").count(), 1);

    super::write_model_family_row_artifact(
        cosmos::MODEL_FAMILY_FIXTURE,
        cosmos::MODEL_FAMILY_FEATURE_ID,
        cosmos::MODEL_FAMILY_IDENTIFIER,
        cosmos::MODEL_FAMILY_SOURCE_ORDINAL,
        "cosmosi2vpredict2_comfy_model_0072",
        &[
            "source-provenance-catalog-and-canonical-cosmos-ownership",
            "source-exact-two-b-and-fourteen-b-i2v-profiles",
            "predict2-marker-packed-channels-geometry-rope-and-memory-delegation",
            "model-store-net-prefix-detection",
            "transactional-predict2-component-mapping-and-checkpoints",
            "patch-order-memory-oom-dtype-device-cancellation",
            "t2i-general-anima-partial-ambiguous-and-layout-rejection",
        ],
    )?;
    Ok(())
}

#[test]
fn val_model_family_row_001_cosmosi2vpredict2_model_store_mapping_forward_patch_and_memory()
-> Result<(), Box<dyn std::error::Error>> {
    let registry =
        ModelFamilyRegistry::checked_registrations(&[cosmos::MODEL_FAMILY_REGISTRATION])?;
    let probe = probe_through_model_store()?;
    assert_eq!(probe.format_identities(), ["safetensors"]);
    assert_eq!(probe.unet_prefix_selection()?.prefix(), "net.");
    assert!(!probe.metadata.contains_key("image_model"));
    assert!(!probe.metadata.contains_key("in_channels"));
    assert!(!probe.metadata.contains_key("model_layout"));
    let resolved = registry.resolve(&probe)?;
    assert_eq!(
        resolved.detection().identity.feature_id(),
        "COMFY-MODEL-0072"
    );
    assert_eq!(resolved.source_ordinal(), 44);
    assert_eq!(resolved.detection().score, 1_000);
    assert_eq!(resolved.detection().evidence.len(), 2);
    assert!(
        resolved
            .detection()
            .evidence
            .iter()
            .any(|evidence| evidence.contains("AnyKeyPresent"))
    );
    assert!(
        resolved
            .detection()
            .evidence
            .iter()
            .any(|evidence| evidence.contains("AnyTensorDimensionValue"))
    );
    assert_eq!(resolved.profile().latent_identifier, "Wan21");
    assert_eq!(resolved.profile().memory_estimator.bytes_per_parameter, 1);

    let candidates = resolved.clip_target().candidates();
    assert_eq!(candidates.len(), 1);
    assert_eq!(
        candidates[0].tokenizer().identifier(),
        "comfy.text_encoders.cosmos.CosmosT5Tokenizer"
    );
    assert_eq!(
        candidates[0].clip_model().target().as_str(),
        "comfy.text_encoders.cosmos.te"
    );
    assert!(matches!(
        candidates[0].clip_model().invocation(),
        ModelClipModelInvocation::Factory { configuration }
            if matches!(configuration.as_slice(), [ModelClipConfigurationFact::Expand { source }]
                if source.as_str() == "comfy.text_encoders.sd3_clip.t5_xxl_detect")
    ));

    let (backend, authority) = CpuWorkspaceAuthority::create_backend(8 * 1024 * 1024)?;
    let cancellation = CancellationToken::default();
    let context = backend.execution_context(
        StreamId::DEFAULT,
        authority.authorize_workspace(4 * 1024 * 1024)?,
        &cancellation,
    );
    let source = source_tensors(&backend, &context, DType::F32, false)?;
    let mapped = resolved.map_state_dictionary(
        &ModelStateTransaction::new(&backend, &context),
        ARTIFACT_DIGEST,
        &source,
    )?;
    assert_eq!(mapped.components().len(), 3);
    assert!(
        mapped
            .component("model")
            .is_some_and(|model| { model.contains_key("native.blocks.0.mlp.layer1.weight") })
    );
    assert!(mapped.component("vae").is_some());
    assert!(mapped.component("text_encoder").is_some());

    let weights = resolved.map_primary_weights(
        &ModelStateTransaction::new(&backend, &context),
        ARTIFACT_DIGEST,
        &source,
    )?;
    let model = build_model_family_for_probe(
        &registry,
        &probe,
        weights,
        options(DType::F32, RESOLVED_MEMORY_BYTES),
    )?;
    assert_eq!(model.memory_estimate().total_bytes, RESOLVED_MEMORY_BYTES);
    let input = tensor(&backend, &[1, 2], &[1.0, 2.0], DType::F32, &context)?;
    let checkpoints = model.forward_checkpoints(&backend, &input, &context)?;
    assert_checkpoint(
        &backend,
        &context,
        &checkpoints,
        "predict2_mlp_projection",
        &[1.4621172, 0.8807971],
    )?;
    assert_checkpoint(
        &backend,
        &context,
        &checkpoints,
        "video_output",
        &[0.0, 0.96402675],
    )?;

    let patch = PatchGraph::checked(
        ARTIFACT_DIGEST,
        vec![PatchOperation {
            identifier: "cosmosi2vpredict2-mlp-delta".to_owned(),
            kind: PatchKind::Lora,
            scale: 1.0,
            targets: vec![PatchTarget {
                key: "native.blocks.0.mlp.layer1.weight".to_owned(),
                expected_shape: vec![2, 2],
                values: vec![1.0, 0.0, 0.0, 1.0],
                application: PatchApplication::Add,
            }],
        }],
    )?;
    let patched = model.with_weights(patch.apply(&backend, model.weights(), &context)?)?;
    let patched_checkpoints = patched.forward_checkpoints(&backend, &input, &context)?;
    assert_checkpoint(
        &backend,
        &context,
        &patched_checkpoints,
        "video_output",
        &[0.0, -0.9640262],
    )?;

    let replace_then_add = ordered_patch_graph(true)?;
    let add_then_replace = ordered_patch_graph(false)?;
    assert_ne!(
        replace_then_add.identity().ordered_digest,
        add_then_replace.identity().ordered_digest
    );
    let first = replace_then_add.apply(&backend, model.weights(), &context)?;
    let second = add_then_replace.apply(&backend, model.weights(), &context)?;
    assert_ne!(
        tensor_to_f32_with_context_exact_native(
            &backend,
            &first.tensors()["native.blocks.0.mlp.layer1.weight"],
            &context,
        )?,
        tensor_to_f32_with_context_exact_native(
            &backend,
            &second.tensors()["native.blocks.0.mlp.layer1.weight"],
            &context,
        )?
    );

    let weights = resolved.map_primary_weights(
        &ModelStateTransaction::new(&backend, &context),
        ARTIFACT_DIGEST,
        &source,
    )?;
    assert!(matches!(
        build_model_family_for_probe(
            &registry,
            &probe,
            weights,
            options(DType::F32, RESOLVED_MEMORY_BYTES - 1),
        ),
        Err(ModelFamilyError::OutOfMemory {
            required: RESOLVED_MEMORY_BYTES,
            budget,
        }) if budget == RESOLVED_MEMORY_BYTES - 1
    ));
    Ok(())
}

#[test]
fn val_model_family_row_001_cosmosi2vpredict2_dtype_and_typed_failures()
-> Result<(), Box<dyn std::error::Error>> {
    let registry =
        ModelFamilyRegistry::checked_registrations(&[cosmos::MODEL_FAMILY_REGISTRATION])?;
    let probe =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 17, 2_048, false, false, "native"))?;
    let resolved = registry.resolve(&probe)?;
    let (backend, authority) = CpuWorkspaceAuthority::create_backend(8 * 1024 * 1024)?;
    let cancellation = CancellationToken::default();
    let context = backend.execution_context(
        StreamId::DEFAULT,
        authority.authorize_workspace(4 * 1024 * 1024)?,
        &cancellation,
    );

    for dtype in [DType::Bf16, DType::F16, DType::F32] {
        let source = source_tensors(&backend, &context, dtype, false)?;
        let weights = resolved.map_primary_weights(
            &ModelStateTransaction::new(&backend, &context),
            ARTIFACT_DIGEST,
            &source,
        )?;
        build_model_family_for_probe(
            &registry,
            &probe,
            weights,
            options(dtype, RESOLVED_MEMORY_BYTES),
        )?;
    }

    let source = source_tensors(&backend, &context, DType::F32, false)?;
    let weights = resolved.map_primary_weights(
        &ModelStateTransaction::new(&backend, &context),
        ARTIFACT_DIGEST,
        &source,
    )?;
    assert!(matches!(
        build_model_family_for_probe(
            &registry,
            &probe,
            weights,
            options(DType::F64, RESOLVED_MEMORY_BYTES),
        ),
        Err(ModelFamilyError::UnsupportedDType(DType::F64))
    ));
    let weights = resolved.map_primary_weights(
        &ModelStateTransaction::new(&backend, &context),
        ARTIFACT_DIGEST,
        &source,
    )?;
    let mut unsupported_device = options(DType::F32, RESOLVED_MEMORY_BYTES);
    unsupported_device.device = DeviceKind::Metal;
    assert!(matches!(
        build_model_family_for_probe(&registry, &probe, weights, unsupported_device),
        Err(ModelFamilyError::UnsupportedDevice(DeviceKind::Metal))
    ));

    let partial_probe =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 17, 2_048, true, false, "native"))?;
    let partial_resolved = registry.resolve(&partial_probe)?;
    let partial = source_tensors(&backend, &context, DType::F32, true)?;
    assert!(matches!(
        partial_resolved.map_state_dictionary(
            &ModelStateTransaction::new(&backend, &context),
            ARTIFACT_DIGEST,
            &partial,
        ),
        Err(ModelFamilyError::MissingComponentKey { component, key })
            if component == "model" && key == "native.final_layer.linear.weight"
    ));

    let t2i =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 16, 2_048, false, false, "native"))?;
    assert!(matches!(
        registry.detect(&t2i),
        Err(ModelFamilyError::NoDetectionMatch)
    ));
    let mut mismatched_facts = parsed_facts(DType::F32, 16, 2_048, false, false, "native");
    mismatched_facts.formats[0]
        .metadata
        .insert("in_channels".to_owned(), "17".to_owned());
    let mismatch = ModelProbe::from_parsed_facts(mismatched_facts)?;
    assert!(matches!(
        registry.resolve(&mismatch),
        Err(ModelFamilyError::NoDetectionMatch)
    ));

    let malformed =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 17, 4_096, false, false, "native"))?;
    assert!(matches!(
        registry.resolve(&malformed),
        Err(ModelFamilyError::InvalidSelectorOutput(message))
            if message.contains("expected 2048 or 5120")
    ));
    let anima =
        ModelProbe::from_parsed_facts(parsed_facts(DType::F32, 17, 2_048, false, true, "native"))?;
    assert!(matches!(
        registry.resolve(&anima),
        Err(ModelFamilyError::InvalidSelectorOutput(message)) if message.contains("Anima marker")
    ));

    let mut general_facts = parsed_facts(DType::F32, 17, 2_048, false, false, "native");
    general_facts
        .tensors
        .remove("net.blocks.0.mlp.layer1.weight");
    let general = ModelProbe::from_parsed_facts(general_facts)?;
    assert!(matches!(
        cosmos::configuration_for_probe(&general),
        Err(ModelFamilyError::InvalidSelectorOutput(message))
            if message.contains("missing Cosmos Predict2 marker")
    ));
    let spoofed_layout = ModelProbe::from_parsed_facts(parsed_facts(
        DType::F32,
        17,
        2_048,
        false,
        false,
        "diffusers",
    ))?;
    assert!(registry.resolve(&spoofed_layout).is_ok());

    let mut unexpected_facts = parsed_facts(DType::F32, 17, 2_048, false, false, "native");
    unexpected_facts.tensors.insert(
        "unexpected.weight".to_owned(),
        ModelParsedTensorFact {
            shape: vec![1],
            storage_dtype: DType::F32.catalog_name().to_owned(),
        },
    );
    let unexpected_probe = ModelProbe::from_parsed_facts(unexpected_facts)?;
    let unexpected_resolved = registry.resolve(&unexpected_probe)?;
    let mut unexpected = source.clone();
    unexpected.insert(
        "unexpected.weight".to_owned(),
        tensor(&backend, &[1], &[1.0], DType::F32, &context)?,
    );
    assert!(matches!(
        unexpected_resolved.map_state_dictionary(
            &ModelStateTransaction::new(&backend, &context),
            ARTIFACT_DIGEST,
            &unexpected,
        ),
        Err(ModelFamilyError::UnexpectedKeys(keys)) if keys == ["unexpected.weight"]
    ));

    let ambiguous = ModelFamilyRegistry::checked_registrations(&AMBIGUOUS_REGISTRATIONS)?;
    assert!(matches!(
        ambiguous.detect(&probe),
        Err(ModelFamilyError::AmbiguousDetection { score: 1_000, .. })
    ));

    let cancelled = CancellationToken::default();
    cancelled.cancel();
    let cancelled_context = backend.execution_context(
        StreamId::DEFAULT,
        authority.authorize_workspace(4 * 1024 * 1024)?,
        &cancelled,
    );
    assert!(matches!(
        resolved.map_state_dictionary(
            &ModelStateTransaction::new(&backend, &cancelled_context),
            ARTIFACT_DIGEST,
            &source,
        ),
        Err(ModelFamilyError::Cancelled(_))
    ));
    Ok(())
}

fn parsed_facts(
    dtype: DType,
    in_channels: u64,
    model_channels: u64,
    omit_final: bool,
    anima: bool,
    layout: &str,
) -> ModelParsedFacts {
    let mut tensors = BTreeMap::new();
    for (key, shape) in model_shapes(in_channels, model_channels, omit_final, anima) {
        tensors.insert(
            format!("net.{key}"),
            ModelParsedTensorFact {
                shape,
                storage_dtype: dtype.catalog_name().to_owned(),
            },
        );
    }
    for key in [
        "first_stage_model.decoder.weight",
        "cond_stage_model.t5xxl.transformer.weight",
    ] {
        tensors.insert(
            key.to_owned(),
            ModelParsedTensorFact {
                shape: vec![1],
                storage_dtype: dtype.catalog_name().to_owned(),
            },
        );
    }
    let mut metadata = BTreeMap::new();
    if layout != "native" {
        metadata.insert("model_layout".to_owned(), layout.to_owned());
    }
    ModelParsedFacts {
        tensors,
        formats: vec![ModelParsedFormatFact {
            identity: "safetensors".to_owned(),
            metadata,
        }],
    }
}

fn model_shapes(
    in_channels: u64,
    model_channels: u64,
    omit_final: bool,
    anima: bool,
) -> Vec<(String, Vec<u64>)> {
    let mut shapes = vec![
        (
            "x_embedder.proj.1.weight".to_owned(),
            vec![model_channels, (in_channels + 1) * 4],
        ),
        ("blocks.0.mlp.layer1.weight".to_owned(), vec![2, 2]),
        ("t_embedder.1.linear_1.weight".to_owned(), vec![2, 2]),
        ("t_embedder.1.linear_2.weight".to_owned(), vec![2, 2]),
        ("t_embedding_norm.weight".to_owned(), vec![2]),
    ];
    if !omit_final {
        shapes.push(("final_layer.linear.weight".to_owned(), vec![2, 2]));
    }
    if anima {
        shapes.push((
            "llm_adapter.blocks.0.cross_attn.q_proj.weight".to_owned(),
            vec![2, 2],
        ));
    }
    shapes.sort_by(|left, right| left.0.cmp(&right.0));
    shapes
}

fn source_tensors(
    backend: &CpuBackend,
    context: &ExecutionContext<'_>,
    dtype: DType,
    omit_final: bool,
) -> Result<BTreeMap<String, Tensor>, Box<dyn std::error::Error>> {
    let mut source = BTreeMap::new();
    for (key, shape) in model_shapes(17, 2_048, omit_final, false) {
        let values = match key.as_str() {
            "t_embedder.1.linear_1.weight" => vec![1.0, 0.0, 0.0, 1.0],
            "blocks.0.mlp.layer1.weight" => vec![2.0, 0.0, 0.0, 0.5],
            "final_layer.linear.weight" => vec![1.0, 1.0, 1.0, -1.0],
            _ => vec![0.0; usize::try_from(shape.iter().product::<u64>())?],
        };
        source.insert(
            format!("net.{key}"),
            tensor(backend, &shape, &values, dtype, context)?,
        );
    }
    source.insert(
        "first_stage_model.decoder.weight".to_owned(),
        tensor(backend, &[1], &[1.0], dtype, context)?,
    );
    source.insert(
        "cond_stage_model.t5xxl.transformer.weight".to_owned(),
        tensor(backend, &[1], &[1.0], dtype, context)?,
    );
    Ok(source)
}

fn probe_through_model_store() -> Result<ModelProbe, Box<dyn std::error::Error>> {
    let directory = tempfile::tempdir()?;
    let model_path = directory.path().join("cosmosi2vpredict2.safetensors");
    write_safetensors(&model_path)?;
    let mut index = ArtifactIndex::default();
    index.add_root(ArtifactRoot::canonical(
        "cosmosi2vpredict2-row",
        "checkpoints",
        directory.path(),
        ["safetensors"],
    )?)?;
    let cancellation = CancellationToken::default();
    index.refresh(&cancellation)?;
    let key = ArtifactKey::new("cosmosi2vpredict2-row", "cosmosi2vpredict2.safetensors")?;
    let mut store = ModelStore::new(ParserLimits::default())?;
    let loaded = store.load(&index, &key, &cancellation)?;
    Ok(store.family_probe(&loaded, &cancellation)?)
}

fn write_safetensors(path: &Path) -> Result<(), Box<dyn std::error::Error>> {
    let mut header = serde_json::Map::new();
    let mut shapes = model_shapes(17, 2_048, false, false)
        .into_iter()
        .map(|(key, shape)| (format!("net.{key}"), shape))
        .collect::<Vec<_>>();
    shapes.extend([
        ("first_stage_model.decoder.weight".to_owned(), vec![1]),
        (
            "cond_stage_model.t5xxl.transformer.weight".to_owned(),
            vec![1],
        ),
    ]);
    let mut data = Vec::new();
    for (key, shape) in shapes {
        let start = data.len();
        let elements = shape.iter().try_fold(1_u64, |total, dimension| {
            total
                .checked_mul(*dimension)
                .ok_or("fixture shape overflow")
        })?;
        for _ in 0..elements {
            data.extend_from_slice(&0.0_f32.to_le_bytes());
        }
        header.insert(
            key,
            serde_json::json!({
                "dtype": "F32",
                "shape": shape,
                "data_offsets": [start, data.len()],
            }),
        );
    }
    let header = serde_json::to_vec(&header)?;
    let mut file = std::fs::File::create(path)?;
    file.write_all(&u64::try_from(header.len())?.to_le_bytes())?;
    file.write_all(&header)?;
    file.write_all(&data)?;
    Ok(())
}

fn tensor(
    backend: &CpuBackend,
    shape: &[u64],
    values: &[f32],
    dtype: DType,
    context: &ExecutionContext<'_>,
) -> Result<Tensor, Box<dyn std::error::Error>> {
    Ok(tensor_from_f32_with_context_exact_native(
        backend,
        shape,
        values,
        dtype,
        backend.device(),
        context,
    )?)
}

fn options(dtype: DType, memory_budget_bytes: u64) -> NativeFamilyBuildOptions {
    NativeFamilyBuildOptions {
        dtype,
        device: DeviceKind::Cpu,
        activation_elements: 2,
        memory_budget_bytes,
        allow_unexpected_weights: false,
    }
}

fn assert_checkpoint(
    backend: &CpuBackend,
    context: &ExecutionContext<'_>,
    checkpoints: &[comfy_model::ModelForwardCheckpoint],
    name: &str,
    expected: &[f32],
) -> Result<(), Box<dyn std::error::Error>> {
    let checkpoint = checkpoints
        .iter()
        .find(|checkpoint| checkpoint.name == name)
        .ok_or("CosmosI2VPredict2 checkpoint is missing")?;
    let actual = tensor_to_f32_with_context_exact_native(backend, &checkpoint.tensor, context)?;
    assert_eq!(actual.len(), expected.len());
    for (actual, expected) in actual.iter().zip(expected) {
        assert!(
            (actual - expected).abs() <= 1.0e-5,
            "{name}: {actual} != {expected}"
        );
    }
    Ok(())
}

fn ordered_patch_graph(replace_first: bool) -> Result<PatchGraph, Box<dyn std::error::Error>> {
    let replacement = PatchOperation {
        identifier: "cosmosi2vpredict2-ordered-replacement".to_owned(),
        kind: PatchKind::Replacement,
        scale: 1.0,
        targets: vec![PatchTarget {
            key: "native.blocks.0.mlp.layer1.weight".to_owned(),
            expected_shape: vec![2, 2],
            values: vec![1.0, 0.0, 0.0, 1.0],
            application: PatchApplication::Replace,
        }],
    };
    let addition = PatchOperation {
        identifier: "cosmosi2vpredict2-ordered-addition".to_owned(),
        kind: PatchKind::Lora,
        scale: 1.0,
        targets: vec![PatchTarget {
            key: "native.blocks.0.mlp.layer1.weight".to_owned(),
            expected_shape: vec![2, 2],
            values: vec![1.0, 0.0, 0.0, 1.0],
            application: PatchApplication::Add,
        }],
    };
    Ok(PatchGraph::checked(
        ARTIFACT_DIGEST,
        if replace_first {
            vec![replacement, addition]
        } else {
            vec![addition, replacement]
        },
    )?)
}

const fn ratio(numerator: u64, denominator: u64) -> CosmosRatio {
    CosmosRatio {
        numerator,
        denominator,
    }
}

fn fixture_directory() -> std::path::PathBuf {
    Path::new(env!("CARGO_MANIFEST_DIR"))
        .join("../comfy_test_support/fixtures/models")
        .join(cosmos::MODEL_FAMILY_FIXTURE)
}

fn sha256(bytes: &[u8]) -> String {
    format!("{:x}", Sha256::digest(bytes))
}
