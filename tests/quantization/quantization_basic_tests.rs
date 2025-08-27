//! Basic quantization functionality tests
//!
//! Tests core quantization functionality to ensure it works correctly.

#[cfg(test)]
mod tests {
    use tracing::debug;
    use std::sync::Arc;
    use proximadb::compute::{
        UnifiedQuantizationEngine, UnifiedQuantizationLevel, QuantizationLevelType,
        ProductQuantization, BinaryQuantization, UniformQuantization, ScalarQuantization,
        UnifiedDistanceCompute, InMemoryCodebookStore, DistanceMetric
    };
    use proximadb::storage::engines::viper::{
        VectorQuantizationEngine, QuantizationConfig as ViperQuantizationConfig, 
        QuantizationLevel
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
                vector,
                metadata: vec![],
                timestamp: chrono::Utc::now().timestamp() as u32,
                updated_at: Some(chrono::Utc::now().timestamp() as u32),
                expires_at: None,
                version: Some(1),
                rank: None,
                score: None,
                distance: None,
            }
        }).collect()
    }

    #[tokio::test]
    async fn test_product_quantization_basic() {
        // Initialize hardware capabilities
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        // Test basic Product Quantization functionality using UnifiedQuantizationEngine
        let _level = UnifiedQuantizationLevel {
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
        let training_vectors = generate_test_vectors(100, 64); // 64 dimensions, divisible by 8
        
        // Create a simple codebook for testing (in real usage, this would be trained)
        // For now, we'll skip training and just test direct quantization
        
        // Test quantization with scalar quantization instead (which doesn't need codebook)
        let scalar_level = UnifiedQuantizationLevel::int8();
        let test_vectors = generate_test_vectors(10, 64);
        let mut quantized = Vec::new();
        for vector in &test_vectors {
            let q = engine.quantize(vector, &scalar_level).await.unwrap();
            quantized.push(q);
        }
        
        assert_eq!(quantized.len(), test_vectors.len());
        
        // Each quantized vector should have data
        for qv in &quantized {
            assert!(!qv.data.is_empty());
            assert_eq!(qv.quantization_level.level_type, scalar_level.level_type);
        }
        
        // Test distance computation
        let query = &test_vectors[0];
        let quantized_query = engine.quantize(query, &scalar_level).await.unwrap();
        let mut distances = Vec::new();
        for qv in &quantized {
            let distance = engine.calculate_distance(query, qv, &DistanceMetric::Euclidean).await.unwrap();
            distances.push(distance);
        }
        assert_eq!(distances.len(), quantized.len());
        
        // Distance to self should be smallest (approximately)
        let self_distance = distances[0];
        let min_distance = distances.iter().fold(f32::INFINITY, |a, b| a.min(b.rank_value));
        assert!(self_distance.rank_value <= min_distance + 0.1);
    }

    #[tokio::test]
    async fn test_quantization_levels() {
        // Initialize hardware capabilities
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        // Test different quantization levels using unified API
        let distance_compute = Arc::new(UnifiedDistanceCompute::default());
        let codebook_store = Arc::new(InMemoryCodebookStore::new());
        let engine = UnifiedQuantizationEngine::new(distance_compute, codebook_store);
        
        let levels = vec![
            UnifiedQuantizationLevel {
                level_type: Some(QuantizationLevelType::Uniform(UniformQuantization {
                    bits: 8,
                    scale: Some(1.0),
                    offset: Some(0.0),
                })),
            },
            UnifiedQuantizationLevel {
                level_type: Some(QuantizationLevelType::Uniform(UniformQuantization {
                    bits: 4,
                    scale: Some(1.0),
                    offset: Some(0.0),
                })),
            },
            UnifiedQuantizationLevel {
                level_type: Some(QuantizationLevelType::Scalar(ScalarQuantization {
                    bits: 8,
                    scale: 1.0,
                    offset: 0.0,
                    clamp_values: true,
                })),
            },
            UnifiedQuantizationLevel {
                level_type: Some(QuantizationLevelType::Binary(BinaryQuantization {
                    threshold: Some(0.0),
                    sign_based: false,
                })),
            },
        ];

        for level in levels {
            // Test that engine can quantize with this level
            let test_vector = vec![1.0; 64];
            let quantized = engine.quantize(&test_vector, &level).await.unwrap();
            
            // Basic validation
            assert!(!quantized.data.is_empty());
            assert_eq!(quantized.quantization_level.level_type, level.level_type);
            
            debug!("Level type: {:?}", level.level_type);
        }
    }

    #[tokio::test]
    async fn test_viper_quantization_engine() {
        // Test VIPER quantization engine
        let config = ViperQuantizationConfig {
            level: QuantizationLevel::uniform_8bit(),
            adaptive_quantization: false,
            pq_subvectors: 8,
            training_sample_size: 100,
            quality_threshold: 0.9,
        };

        let mut engine = VectorQuantizationEngine::new(config);
        
        // Generate training data
        let training_vectors = generate_test_vectors(50, 128);
        
        // Train quantization model
        let model = engine.train_model(&training_vectors).unwrap();
        
        assert_eq!(model.dimension, 128);
        assert!(model.quality_metrics.compression_ratio > 1.0);
        assert!(model.quality_metrics.search_quality_retention > 0.0);
        
        // Test quantization of vector records
        let test_records = generate_vector_records(10, 128);
        let quantized_vectors = engine.quantize_vectors(&test_records).unwrap();
        
        assert_eq!(quantized_vectors.len(), test_records.len());
        
        // Calculate storage savings
        let (original_bytes, quantized_bytes, compression_ratio) = 
            engine.calculate_storage_savings(&test_records, &quantized_vectors);
        
        assert!(original_bytes > quantized_bytes);
        assert!(compression_ratio > 1.0);
        
        debug!("Storage savings: {:.2}x compression ({} -> {} bytes)", 
                 compression_ratio, original_bytes, quantized_bytes);
    }

    #[tokio::test]
    async fn test_quantization_edge_cases() {
        // Test edge cases and error conditions
        
        // 1. Empty training data
        let config = ViperQuantizationConfig::default();
        let mut engine = VectorQuantizationEngine::new(config);
        
        let empty_vectors: Vec<Vec<f32>> = vec![];
        assert!(engine.train_model(&empty_vectors).is_err());
        
        // 2. Mismatched dimensions
        let mismatched_vectors = vec![
            vec![1.0, 2.0, 3.0],
            vec![1.0, 2.0], // Wrong dimension
        ];
        assert!(engine.train_model(&mismatched_vectors).is_err());
        
        // 3. Invalid quantization parameters
        let invalid_level = QuantizationLevel::ProductQuantization {
            bits_per_code: 0, // Invalid
            num_subvectors: 8,
        };
        assert!(invalid_level.validate().is_err());
        
        // 4. Very small vectors (should still work)
        let tiny_vectors = vec![vec![1.0], vec![2.0]];
        let mut tiny_engine = VectorQuantizationEngine::new(ViperQuantizationConfig {
            level: QuantizationLevel::uniform_8bit(),
            adaptive_quantization: false,
            pq_subvectors: 1,
            training_sample_size: 2,
            quality_threshold: 0.5,
        });
        
        // This should work even with tiny vectors
        assert!(tiny_engine.train_model(&tiny_vectors).is_ok());
    }

    #[tokio::test]
    async fn test_quantization_memory_efficiency() {
        // Test that quantization actually reduces memory usage
        let dimensions = 256;
        let num_vectors = 100;
        
        let config = ViperQuantizationConfig {
            level: QuantizationLevel::uniform_4bit(), // 4-bit should give 8x compression
            adaptive_quantization: false,
            pq_subvectors: 8,
            training_sample_size: num_vectors,
            quality_threshold: 0.8,
        };

        let mut engine = VectorQuantizationEngine::new(config);
        
        // Generate test data
        let training_vectors = generate_test_vectors(num_vectors, dimensions);
        let test_records = generate_vector_records(50, dimensions);
        
        // Train and quantize
        engine.train_model(&training_vectors).unwrap();
        let quantized = engine.quantize_vectors(&test_records).unwrap();
        
        // Calculate memory savings
        let (original_bytes, quantized_bytes, compression_ratio) = 
            engine.calculate_storage_savings(&test_records, &quantized);
        
        // 4-bit quantization should achieve significant compression
        assert!(compression_ratio > 6.0); // Should be close to 8x for 4-bit
        assert!(original_bytes > quantized_bytes * 6);
        
        debug!("Memory efficiency test:");
        debug!("  Original: {} bytes", original_bytes);
        debug!("  Quantized: {} bytes", quantized_bytes);
        debug!("  Compression: {:.1}x", compression_ratio);
        debug!("  Savings: {:.1}%", (1.0 - quantized_bytes as f32 / original_bytes as f32) * 100.0);
    }

    #[tokio::test]
    async fn test_quantization_model_serialization() {
        // Test that quantization models can be serialized/deserialized
        let config = ViperQuantizationConfig::default();
        let mut engine = VectorQuantizationEngine::new(config);
        
        let training_vectors = generate_test_vectors(20, 64);
        let model = engine.train_model(&training_vectors).unwrap();
        
        // Serialize model to JSON
        let serialized = serde_json::to_string(&model).unwrap();
        assert!(!serialized.is_empty());
        
        // Deserialize model
        let deserialized_model: proximadb::storage::engines::viper::quantization::QuantizationModel = 
            serde_json::from_str(&serialized).unwrap();
        
        // Verify model integrity
        assert_eq!(model.model_id, deserialized_model.model_id);
        assert_eq!(model.dimension, deserialized_model.dimension);
        assert_eq!(model.level, deserialized_model.level);
        
        debug!("Model serialization test passed");
        debug!("  Model ID: {}", model.model_id);
        debug!("  Dimension: {}", model.dimension);
        debug!("  Level: {:?}", model.level);
    }

    // ============================================================================
    // Comprehensive SST Quantization Tests
    // ============================================================================

    #[tokio::test]
    async fn test_sst_binary_filtering_reduction() {
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        use proximadb::compute::quantization::{
            StorageQuantizationEngine, StorageQuantizationConfig, SearchStage,
        };
        
        // Create storage quantization engine
        let distance_compute = Arc::new(UnifiedDistanceCompute::default());
        let codebook_store = Arc::new(InMemoryCodebookStore::new());
        let unified_engine = Arc::new(UnifiedQuantizationEngine::new(
            distance_compute.clone(),
            codebook_store,
        ));
        
        let config = StorageQuantizationConfig::default();
        let engine = StorageQuantizationEngine::new(
            unified_engine,
            distance_compute,
            config,
        );
        
        // Generate clustered test vectors
        let vectors = generate_clustered_vectors(1000, 256, 5);
        
        // Quantize vectors
        let quantized = engine.quantize_batch(&vectors, None).await.unwrap();
        
        // Verify binary sketches present
        for data in &quantized {
            assert!(data.filter.is_some(), "Binary sketch missing");
        }
        
        // Test binary filtering
        let query = vectors[0].clone();
        let stages = engine.progressive_search(
            &query,
            &quantized,
            10,
            &DistanceMetric::Cosine,
        ).await.unwrap();
        
        // Find binary filter stage
        let binary_stage = stages.iter()
            .find(|s| s.stage == SearchStage::BinaryFilter);
        
        if let Some(stage) = binary_stage {
            debug!("Binary filtering achieved {:.1}% reduction", 
                stage.metrics.reduction_percent);
            
            // Should achieve significant reduction
            assert!(
                stage.metrics.reduction_percent >= 80.0,
                "Binary filtering reduction {:.1}% below expected 80%",
                stage.metrics.reduction_percent
            );
        }
    }

    #[tokio::test]
    async fn test_sst_int8_approximation_quality() {
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        use proximadb::compute::quantization::{
            StorageQuantizationEngine, StorageQuantizationConfig,
        };
        
        // Create engine
        let distance_compute = Arc::new(UnifiedDistanceCompute::default());
        let codebook_store = Arc::new(InMemoryCodebookStore::new());
        let unified_engine = Arc::new(UnifiedQuantizationEngine::new(
            distance_compute.clone(),
            codebook_store,
        ));
        
        let config = StorageQuantizationConfig::default();
        let engine = StorageQuantizationEngine::new(
            unified_engine,
            distance_compute,
            config,
        );
        
        // Test vectors
        let vectors = generate_test_vectors(100, 128);
        let quantized = engine.quantize_batch(&vectors, None).await.unwrap();
        
        // Verify INT8 quantization
        for data in &quantized {
            assert!(data.fast.is_some(), "INT8 quantization missing");
        }
        
        // Test approximation quality
        let query = vectors[0].clone();
        let true_distances: Vec<f32> = vectors.iter()
            .map(|v| {
                let dot: f32 = query.iter().zip(v.iter())
                    .map(|(a, b)| a * b)
                    .sum();
                1.0 - dot // Cosine distance
            })
            .collect();
        
        // Get INT8 approximations
        let stages = engine.progressive_search(
            &query,
            &quantized,
            10,
            &DistanceMetric::Cosine,
        ).await.unwrap();
        
        debug!("Progressive search completed with {} stages", stages.len());
    }

    #[tokio::test]
    async fn test_sst_pq_with_distance_tables() {
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        use proximadb::compute::quantization::{
            StorageQuantizationEngine, StorageQuantizationConfig, SearchStage,
        };
        
        // Configure PQ quantization
        let mut config = StorageQuantizationConfig::default();
        config.primary_level = Some(UnifiedQuantizationLevel {
            level_type: Some(QuantizationLevelType::Pq(ProductQuantization {
                num_subvectors: 8,
                bits_per_code: 8,
                codebook_id: None,
                adaptive_subvectors: false,
            })),
        });
        
        let distance_compute = Arc::new(UnifiedDistanceCompute::default());
        let codebook_store = Arc::new(InMemoryCodebookStore::new());
        let unified_engine = Arc::new(UnifiedQuantizationEngine::new(
            distance_compute.clone(),
            codebook_store,
        ));
        
        let mut engine = StorageQuantizationEngine::new(
            unified_engine,
            distance_compute,
            config,
        );
        
        // Train and quantize
        let vectors = generate_test_vectors(500, 256);
        engine.train(&vectors).await.unwrap();
        let quantized = engine.quantize_batch(&vectors, None).await.unwrap();
        
        // Test PQ ranking speed
        let query = vectors[0].clone();
        let start = std::time::Instant::now();
        
        let stages = engine.progressive_search(
            &query,
            &quantized,
            10,
            &DistanceMetric::Euclidean,
        ).await.unwrap();
        
        let elapsed = start.elapsed();
        
        // PQ with distance tables should be fast
        assert!(
            elapsed.as_millis() < 100,
            "PQ search took {}ms, expected < 100ms",
            elapsed.as_millis()
        );
        
        debug!("PQ search with distance tables completed in {}ms", 
            elapsed.as_millis());
    }

    #[tokio::test]
    async fn test_sst_progressive_pipeline_efficiency() {
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        use proximadb::compute::quantization::{
            StorageQuantizationEngine, StorageQuantizationConfig,
        };
        
        // Create engine
        let distance_compute = Arc::new(UnifiedDistanceCompute::default());
        let codebook_store = Arc::new(InMemoryCodebookStore::new());
        let unified_engine = Arc::new(UnifiedQuantizationEngine::new(
            distance_compute.clone(),
            codebook_store,
        ));
        
        let config = StorageQuantizationConfig::default();
        let engine = StorageQuantizationEngine::new(
            unified_engine,
            distance_compute,
            config,
        );
        
        // Large dataset for progressive search
        let vectors = generate_clustered_vectors(5000, 384, 10);
        let quantized = engine.quantize_batch(&vectors, None).await.unwrap();
        
        // Test progressive search
        let query = vectors[250].clone();
        let stages = engine.progressive_search(
            &query,
            &quantized,
            10,
            &DistanceMetric::Cosine,
        ).await.unwrap();
        
        // Track reduction through pipeline
        let initial = quantized.len();
        let mut cumulative_reduction = 0.0;
        
        for stage in &stages {
            if stage.metrics.output_count > 0 {
                cumulative_reduction = 100.0 * (1.0 - stage.metrics.output_count as f32 / initial as f32);
                debug!("{:?}: {:.1}% cumulative reduction", 
                    stage.stage, cumulative_reduction);
            }
        }
        
        // Should achieve > 99% reduction
        assert!(
            cumulative_reduction >= 99.0,
            "Progressive search achieved only {:.1}% reduction",
            cumulative_reduction
        );
    }

    #[tokio::test]
    async fn test_sst_quantization_memory_pooling() {
        let _ = proximadb::core::hardware_capabilities::initialize_hardware_capabilities_default();
        
        use proximadb::core::memory::pool::VectorMemoryPool;
        use proximadb::compute::quantization::{
            StorageQuantizationEngine, StorageQuantizationConfig,
        };
        
        // Create memory pool
        let memory_pool = VectorMemoryPool::new();
        
        // Create engine
        let distance_compute = Arc::new(UnifiedDistanceCompute::default());
        let codebook_store = Arc::new(InMemoryCodebookStore::new());
        let unified_engine = Arc::new(UnifiedQuantizationEngine::new(
            distance_compute.clone(),
            codebook_store,
        ));
        
        let config = StorageQuantizationConfig::default();
        let engine = StorageQuantizationEngine::new(
            unified_engine,
            distance_compute,
            config,
        );
        
        // Perform multiple operations to test pooling
        for i in 0..5 {
            let vectors = generate_test_vectors(100, 256);
            
            // Use pooled buffer
            let mut buffer = memory_pool.serialization_buffers/* TODO: Fix VectorMemoryPool::acquire() method */;
            
            // Quantize
            let quantized = engine.quantize_batch(&vectors, None).await.unwrap();
            
            // Serialize to buffer
            for data in &quantized {
                if let Some(ref primary) = data.primary {
                    buffer.extend_from_slice(&primary.data);
                }
            }
            
            debug!("Iteration {}: processed {} bytes", i, buffer.len());
            // Buffer returns to pool when dropped
        }
        
        // Check pool efficiency
        let stats = memory_pool.get_comprehensive_stats();
        let hit_rate = stats.serialization.hit_rate();
        
        debug!("Memory pool hit rate: {:.1}%", hit_rate * 100.0);
        
        // Should have good reuse
        assert!(
            hit_rate >= 0.6,
            "Pool hit rate {:.1}% below expected 60%",
            hit_rate * 100.0
        );
    }

    // Helper function for generating clustered vectors
    fn generate_clustered_vectors(count: usize, dim: usize, clusters: usize) -> Vec<Vec<f32>> {
        use rand::{Rng, SeedableRng};
        use rand::rngs::StdRng;
        
        let mut rng = StdRng::seed_from_u64(42);
        let mut vectors = Vec::with_capacity(count);
        let per_cluster = count / clusters;
        
        for c in 0..clusters {
            // Generate cluster center
            let mut center = vec![0.0f32; dim];
            for val in &mut center {
                *val = rng.gen_range(-1.0..1.0);
            }
            
            // Generate vectors around center
            for _ in 0..per_cluster {
                let mut vec = center.clone();
                for val in &mut vec {
                    *val += rng.gen_range(-0.1..0.1);
                }
                
                // Normalize
                let norm: f32 = vec.iter().map(|x| x * x).sum::<f32>().sqrt();
                if norm > 0.0 {
                    for val in &mut vec {
                        *val /= norm;
                    }
                }
                
                vectors.push(vec);
            }
        }
        
        // Fill remaining if needed
        while vectors.len() < count {
            vectors.push(generate_test_vectors(1, dim)[0].clone());
        }
        
        vectors
    }
}