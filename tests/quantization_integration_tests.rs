//! Comprehensive integration tests for quantization support
//!
//! These tests ensure quantization works correctly across different storage engines
//! and search scenarios, validating both accuracy and performance.

use anyhow::Result;

use proximadb::compute::{
    UnifiedQuantizationEngine, UnifiedQuantizationLevel, QuantizationLevelType,
    ProductQuantization, BinaryQuantization, UnifiedDistanceCompute, InMemoryCodebookStore
};
use std::sync::Arc;
use proximadb::storage::engines::viper::quantization::{
    VectorQuantizationEngine, QuantizationConfig as ViperQuantizationConfig, QuantizationLevel
};
use proximadb::core::VectorRecord;

/// Generate test vectors for quantization testing
fn generate_test_vectors(count: usize, dimensions: usize) -> Vec<Vec<f32>> {
    (0..count)
        .map(|i| {
            (0..dimensions)
                .map(|j| {
                    let base = (i * dimensions + j) as f32 * 0.001;
                    match i % 4 {
                        0 => base,
                        1 => base.sin(),
                        2 => if base > 0.5 { 1.0 } else { -1.0 },
                        _ => base * base,
                    }
                })
                .collect()
        })
        .collect()
}

/// Generate VectorRecord test data
fn generate_vector_records(count: usize, dimensions: usize) -> Vec<VectorRecord> {
    let vectors = generate_test_vectors(count, dimensions);
    vectors.into_iter().enumerate().map(|(i, vector)| {
        VectorRecord {
            id: Some(format!("vector_{}", i)),
            collection_id: "test_collection".to_string(),
            vector,
            metadata: vec![],
            timestamp: chrono::Utc::now().timestamp_millis(),
            created_at: chrono::Utc::now().timestamp_millis(),
            updated_at: chrono::Utc::now().timestamp_millis(),
            expires_at: None,
            version: 1,
            rank: None,
            score: None,
            distance: None,
        }
    }).collect()
}

#[tokio::test]
async fn test_unified_product_quantization() -> Result<()> {
    // Test Product Quantization using UnifiedQuantizationEngine
    let level = UnifiedQuantizationLevel {
        level_type: Some(QuantizationLevelType::Pq(ProductQuantization {
            bits_per_code: 8,
            num_subvectors: 8,
            codebook_id: None,
            adaptive_subvectors: false,
        })),
    };

    let distance_compute = Arc::new(UnifiedDistanceCompute::default());
    let codebook_store = Arc::new(InMemoryCodebookStore::new());
    let engine = UnifiedQuantizationEngine::new(distance_compute, codebook_store);
    
    // Generate training data
    let training_vectors = generate_test_vectors(1000, 384); // BERT-like dimensions
    
    // Create a simple codebook for testing
    // In practice, PQ would need a pre-trained codebook
    // For this test, we'll use scalar quantization instead
    
    // Test quantization with scalar quantization instead
    let scalar_level = UnifiedQuantizationLevel::int8();
    let test_vectors = generate_test_vectors(100, 384);
    let mut quantized = Vec::new();
    for vector in &test_vectors {
        let q = engine.quantize(vector, &scalar_level).await?;
        quantized.push(q);
    }
    
    assert_eq!(quantized.len(), test_vectors.len());
    
    // Verify each quantized vector has data
    for qv in &quantized {
        assert!(!qv.data.is_empty());
    }
    
    Ok(())
}

#[tokio::test]
async fn test_unified_binary_quantization() -> Result<()> {
    // Test Binary Quantization using UnifiedQuantizationEngine
    let level = UnifiedQuantizationLevel {
        level_type: Some(QuantizationLevelType::Binary(BinaryQuantization {
            threshold: Some(0.0),
            sign_based: true,
        })),
    };

    let distance_compute = Arc::new(UnifiedDistanceCompute::default());
    let codebook_store = Arc::new(InMemoryCodebookStore::new());
    let engine = UnifiedQuantizationEngine::new(distance_compute, codebook_store);
    
    // Generate training data suitable for binary quantization
    let training_vectors: Vec<Vec<f32>> = (0..200)
        .map(|i| {
            (0..64)
                .map(|j| if (i + j) % 2 == 0 { 1.0 } else { -1.0 })
                .collect()
        })
        .collect();
    
    // Binary quantization doesn't need training
    
    // Test quantization
    let test_vectors = training_vectors[0..10].to_vec();
    let mut quantized = Vec::new();
    for vector in &test_vectors {
        let q = engine.quantize(vector, &level).await?;
        quantized.push(q);
    }
    
    assert_eq!(quantized.len(), test_vectors.len());
    
    // Binary quantization should achieve very high compression
    // Binary quantization: 1 bit per dimension, original is 32 bits per float
    let compression_ratio = 32.0; // 32 bits / 1 bit = 32x compression
    assert!(compression_ratio > 30.0); // Should achieve >30x compression
    
    Ok(())
}

#[tokio::test]
async fn test_viper_quantization_integration() -> Result<()> {
    // Test VIPER engine quantization integration
    let config = ViperQuantizationConfig {
        level: QuantizationLevel::pq8(8),
        adaptive_quantization: true,
        pq_subvectors: 8,
        training_sample_size: 100,
        quality_threshold: 0.9,
    };

    let mut engine = VectorQuantizationEngine::new(config);
    
    // Generate training data
    let training_vectors = generate_test_vectors(200, 128);
    
    // Train quantization model
    let model = engine.train_model(&training_vectors)?;
    
    assert_eq!(model.dimension, 128);
    assert!(model.quality_metrics.compression_ratio > 1.0);
    
    // Test quantization of vector records
    let test_records = generate_vector_records(50, 128);
    let quantized_vectors = engine.quantize_vectors(&test_records)?;
    
    assert_eq!(quantized_vectors.len(), test_records.len());
    
    // Calculate storage savings
    let (original_bytes, quantized_bytes, compression_ratio) = 
        engine.calculate_storage_savings(&test_records, &quantized_vectors);
    
    assert!(original_bytes > quantized_bytes);
    assert!(compression_ratio > 1.0);
    
    println!("🔧 VIPER quantization test passed");
    println!("   Model dimension: {}", model.dimension);
    println!("   Compression ratio: {:.2}x", compression_ratio);
    println!("   Storage savings: {} -> {} bytes", original_bytes, quantized_bytes);
    
    Ok(())
}

#[tokio::test]
async fn test_adaptive_quantization_selection() -> Result<()> {
    // Test adaptive quantization selection based on data characteristics
    let config = ViperQuantizationConfig {
        level: QuantizationLevel::pq8(8), // Use PQ8 instead of non-existent adaptive
        adaptive_quantization: true,
        pq_subvectors: 8,
        training_sample_size: 100,
        quality_threshold: 0.9,
    };

    let mut engine = VectorQuantizationEngine::new(config);
    
    // Test with dense vectors (should select PQ or scalar)
    let dense_vectors: Vec<Vec<f32>> = (0..100)
        .map(|i| {
            (0..128)
                .map(|j| ((i * j) as f32).sin() * 0.5 + 0.5)
                .collect()
        })
        .collect();
        
    let dense_model = engine.train_model(&dense_vectors)?;
    // Should select appropriate quantization for dense data
    assert!(matches!(
        dense_model.level, 
        QuantizationLevel::ProductQuantization { .. } | 
        QuantizationLevel::Uniform(_)
    ));
    
    // Test with sparse vectors (should select binary or low-bit)
    let sparse_vectors: Vec<Vec<f32>> = (0..100)
        .map(|i| {
            (0..128)
                .map(|j| if (i + j) % 10 == 0 { 1.0 } else { 0.0 })
                .collect()
        })
        .collect();
        
    let sparse_model = engine.train_model(&sparse_vectors)?;
    // Should select binary or low-bit quantization for sparse data
    assert!(sparse_model.level.bits_per_value() <= 4);
    
    println!("🎯 Adaptive selection results:");
    println!("  Dense data: {:?}", dense_model.level);
    println!("  Sparse data: {:?}", sparse_model.level);
    
    Ok(())
}

#[tokio::test]
async fn test_quantization_error_handling() -> Result<()> {
    // Test error handling in quantization
    let config = ViperQuantizationConfig::default();
    let mut engine = VectorQuantizationEngine::new(config);
    
    // Test with empty vectors
    let empty_vectors: Vec<Vec<f32>> = vec![];
    assert!(engine.train_model(&empty_vectors).is_err());
    
    // Test with mismatched dimensions
    let mismatched_vectors = vec![
        vec![1.0, 2.0, 3.0],
        vec![4.0, 5.0], // Wrong dimension
    ];
    assert!(engine.train_model(&mismatched_vectors).is_err());
    
    // Test with very small vectors (should still work)
    let tiny_vectors = vec![vec![1.0], vec![2.0]];
    let tiny_config = ViperQuantizationConfig {
        level: QuantizationLevel::uniform_8bit(),
        adaptive_quantization: false,
        pq_subvectors: 1,
        training_sample_size: 2,
        quality_threshold: 0.5,
    };
    
    let mut tiny_engine = VectorQuantizationEngine::new(tiny_config);
    assert!(tiny_engine.train_model(&tiny_vectors).is_ok());
    
    println!("✅ Error handling tests passed");
    
    Ok(())
}

#[tokio::test]
async fn test_quantization_quality_metrics() -> Result<()> {
    // Test quantization quality metrics
    let config = ViperQuantizationConfig {
        level: QuantizationLevel::pq8(8),
        adaptive_quantization: false,
        pq_subvectors: 8,
        training_sample_size: 200,
        quality_threshold: 0.9,
    };

    let mut engine = VectorQuantizationEngine::new(config);
    
    // Generate test data
    let training_vectors = generate_test_vectors(200, 256);
    let test_records = generate_vector_records(50, 256);
    
    // Train and quantize
    let model = engine.train_model(&training_vectors)?;
    let quantized = engine.quantize_vectors(&test_records)?;
    
    // Verify quality metrics
    assert!(model.quality_metrics.search_quality_retention > 0.7); // Lower threshold for test
    assert!(model.quality_metrics.compression_ratio > 1.0); // Any compression is good
    // quantization_time_ms is always >= 0 as it's unsigned
    
    // Calculate reconstruction error
    for (i, qv) in quantized.iter().enumerate() {
        let error = qv.reconstruction_error;
        assert!(error < 0.5); // Reasonable reconstruction error
    }
    
    println!("📊 Quality metrics:");
    println!("  Search quality retention: {:.2}%", 
             model.quality_metrics.search_quality_retention * 100.0);
    println!("  Compression ratio: {:.2}x", 
             model.quality_metrics.compression_ratio);
    println!("  Training time: {:.2}ms", 
             model.quality_metrics.quantization_time_ms);
    
    Ok(())
}

#[tokio::test]
async fn test_model_serialization() -> Result<()> {
    // Test that quantization models can be serialized/deserialized
    let config = ViperQuantizationConfig::default();
    let mut engine = VectorQuantizationEngine::new(config);
    
    let training_vectors = generate_test_vectors(50, 64);
    let model = engine.train_model(&training_vectors)?;
    
    // Serialize model to JSON
    let serialized = serde_json::to_string(&model)?;
    assert!(!serialized.is_empty());
    
    // Deserialize model
    let deserialized_model: proximadb::storage::engines::viper::quantization::QuantizationModel = 
        serde_json::from_str(&serialized)?;
    
    // Verify model integrity
    assert_eq!(model.model_id, deserialized_model.model_id);
    assert_eq!(model.dimension, deserialized_model.dimension);
    assert_eq!(model.level, deserialized_model.level);
    
    // Test using deserialized model
    let mut new_engine = VectorQuantizationEngine::new(ViperQuantizationConfig::default());
    new_engine.set_model(deserialized_model);
    
    let test_records = generate_vector_records(10, 64);
    let quantized = new_engine.quantize_vectors(&test_records)?;
    assert_eq!(quantized.len(), test_records.len());
    
    println!("✅ Model serialization test passed");
    
    Ok(())
}

// Performance benchmarks moved to separate performance test file