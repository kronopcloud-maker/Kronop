/**
 * KronopNativeInterface.cpp
 * JNI Bridge for React Native Integration
 * ARM64 Optimized Native Video Processing Engine
 */

#include <jni.h>
#include <android/log.h>
#include <memory>
#include <thread>
#include <mutex>
#include <vector>
#include "FinalOutputCollector.hpp"
#include "Deblur_Core.cpp"
#include "ChunkManager.cpp"
#include "Dynamic_PSF/OpticalFlow.cpp"
#include "Smart_Sharpening/SmartSharpening.cpp"
#include "Advanced_Shaders/ComputeShaders.cpp"
#include "VulkanCompute.cpp"
#include "../../../Master_Control/Output_Gateway/AI3_Sender.hpp"

#define LOG_TAG "KronopNative"
#define LOGI(...) __android_log_print(ANDROID_LOG_INFO, LOG_TAG, __VA_ARGS__)
#define LOGE(...) __android_log_print(ANDROID_LOG_ERROR, LOG_TAG, __VA_ARGS__)

namespace kronop {

// ARM64 Optimization Macros
#ifdef __aarch64__
#define ARM64_NEON_ENABLED 1
#include <arm_neon.h>
#endif

// Global Engine Instance
class KronopEngine {
private:
    std::unique_ptr<DeblurEngine> deblurEngine_;
    std::unique_ptr<ChunkManager> chunkManager_;
    std::unique_ptr<VulkanContext> vulkanContext_;
    std::mutex engineMutex_;
    bool initialized_;
    bool vulkanEnabled_;
    
public:
    KronopEngine() : initialized_(false), vulkanEnabled_(false) {}
    
    bool initialize(int width, int height, bool enableVulkan = true) {
        std::lock_guard<std::mutex> lock(engineMutex_);
        
        if (initialized_) {
            return true;
        }
        
        try {
            LOGI("Initializing Kronop Engine %dx%d", width, height);
            
            // Initialize Deblur Engine with ARM64 optimizations
            deblurEngine_ = std::make_unique<DeblurEngine>();
            bool deblurInit = deblurEngine_->initialize(width, height, 3, true);
            
            if (!deblurInit) {
                LOGE("Failed to initialize Deblur Engine");
                return false;
            }
            
            // Initialize Chunk Manager for large video processing
            TileConfig tileConfig;
            tileConfig.tileWidth = 512;
            tileConfig.tileHeight = 512;
            tileConfig.overlapSize = 16;
            tileConfig.maxTilesInMemory = 8;
            
            chunkManager_ = std::make_unique<ChunkManager>(tileConfig);
            bool chunkInit = chunkManager_->initializeVideoFile("native_stream", width, height, 3);
            
            if (!chunkInit) {
                LOGE("Failed to initialize Chunk Manager");
                return false;
            }
            
            // Initialize Vulkan Pipeline if requested
            vulkanEnabled_ = enableVulkan;
            if (enableVulkan) {
                vulkanContext_ = std::make_unique<VulkanContext>();
                bool vulkanInit = vulkanContext_->initialize();
                
                if (vulkanInit) {
                    LOGI("Vulkan pipeline activated successfully");
                    // Configure Vulkan for optimal performance
                    VulkanConfig vkConfig = vulkanContext_->getConfig();
                    vkConfig.enableComputeShaders = true;
                    vkConfig.enableAsyncProcessing = true;
                    vkConfig.maxConcurrentFrames = 3;
                    
                    // Initialize Vulkan FFT and Wiener Filter
                    auto vulkanFFT = std::make_unique<VulkanFFT>(vkConfig);
                    auto vulkanWiener = std::make_unique<VulkanWienerFilter>(vkConfig);
                    
                    vulkanFFT->initialize(width, height);
                    vulkanWiener->initialize(width, height);
                    
                    LOGI("Vulkan compute shaders ready");
                } else {
                    LOGW("Vulkan initialization failed, falling back to CPU");
                    vulkanEnabled_ = false;
                }
            }
            
            initialized_ = true;
            LOGI("Kronop Engine initialized successfully");
            return true;
            
        } catch (const std::exception& e) {
            LOGE("Engine initialization failed: %s", e.what());
            return false;
        }
    }
    
    bool processFrame(uint8_t* inputData, uint8_t* outputData, int width, int height) {
        std::lock_guard<std::mutex> lock(engineMutex_);
        
        if (!initialized_ || !deblurEngine_) {
            LOGE("Engine not initialized");
            return false;
        }
        
        try {
            auto startTime = std::chrono::high_resolution_clock::now();
            
            // Create frame data structure
            FrameData inputFrame(width, height, 3);
            FrameData outputFrame(width, height, 3);
            
            // Copy input data (ARM64 optimized copy)
            if (vulkanEnabled_ && vulkanContext_) {
                // Use GPU accelerated processing
                memcpy(inputFrame.data.data(), inputData, width * height * 3);
                
                bool success = deblurEngine_->processFrameWithAdvancedFeatures(inputFrame, outputFrame);
                
                if (success) {
                    memcpy(outputData, outputFrame.data.data(), width * height * 3);
                }
                
                auto endTime = std::chrono::high_resolution_clock::now();
                auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(endTime - startTime);
                
                LOGI("GPU processing completed in %ld ms", duration.count());
                return success;
            } else {
                // Use CPU optimized processing with ARM64 NEON
                bool success = processFrameARM64(inputData, outputData, width, height);
                
                auto endTime = std::chrono::high_resolution_clock::now();
                auto duration = std::chrono::duration_cast<std::chrono::milliseconds>(endTime - startTime);
                
                LOGI("CPU processing completed in %ld ms", duration.count());
                return success;
            }
            
        } catch (const std::exception& e) {
            LOGE("Frame processing failed: %s", e.what());
            return false;
        }
    }
    
    bool processFrameARM64(uint8_t* input, uint8_t* output, int width, int height) {
#ifdef __aarch64__
        // ARM64 NEON optimized processing
        int totalPixels = width * height;
        int simdPixels = totalPixels & ~7; // Process 8 pixels at once
        
        // Process RGB channels with NEON
        for (int i = 0; i < simdPixels; i += 8) {
            // Load 8 pixels for each channel
            uint8x8x3_t pixels = vld3_u8(&input[i * 3]);
            
            // Apply contrast enhancement (multiply by 1.2)
            uint16x8_t r = vmovl_u8(pixels.val[0]);
            uint16x8_t g = vmovl_u8(pixels.val[1]);
            uint16x8_t b = vmovl_u8(pixels.val[2]);
            
            // Multiply by 12/10 (1.2)
            r = vqdmulhq_n_s16(vreinterpretq_s16_u16(r), 12);
            g = vqdmulhq_n_s16(vreinterpretq_s16_u16(g), 12);
            b = vqdmulhq_n_s16(vreinterpretq_s16_u16(b), 12);
            
            // Divide by 10 and clamp
            r = vqshrq_n_s16(r, 3);
            g = vqshrq_n_s16(g, 3);
            b = vqshrq_n_s16(b, 3);
            
            // Convert back to uint8 and store
            pixels.val[0] = vqmovun_s16(r);
            pixels.val[1] = vqmovun_s16(g);
            pixels.val[2] = vqmovun_s16(b);
            
            vst3_u8(&output[i * 3], pixels);
        }
        
        // Process remaining pixels
        for (int i = simdPixels; i < totalPixels; ++i) {
            for (int c = 0; c < 3; ++c) {
                int idx = i * 3 + c;
                uint16_t val = input[idx];
                val = (val * 12) / 10; // 1.2x contrast
                output[idx] = (uint8_t)std::min(255, val);
            }
        }
        
        return true;
#else
        // Fallback for non-ARM64 platforms
        int totalPixels = width * height * 3;
        for (int i = 0; i < totalPixels; ++i) {
            uint16_t val = input[i];
            val = (val * 12) / 10; // 1.2x contrast
            output[i] = (uint8_t)std::min(255, val);
        }
        return true;
#endif
    }
    
    bool processBatch(uint8_t* inputData, uint8_t* outputData, int width, int height, int frameCount) {
        std::lock_guard<std::mutex> lock(engineMutex_);
        
        if (!initialized_ || !chunkManager_) {
            LOGE("Engine not initialized for batch processing");
            return false;
        }
        
        try {
            LOGI("Processing batch of %d frames", frameCount);
            
            // Use chunk manager for efficient batch processing
            std::vector<FrameData> inputFrames(frameCount);
            std::vector<FrameData> outputFrames(frameCount);
            
            // Prepare input frames
            for (int i = 0; i < frameCount; ++i) {
                inputFrames[i] = FrameData(width, height, 3);
                memcpy(inputFrames[i].data.data(), &inputData[i * width * height * 3], width * height * 3);
            }
            
            // Process batch
            bool success = deblurEngine_->deblurBatch(inputFrames, outputFrames);
            
            // Copy output data
            for (int i = 0; i < frameCount && success; ++i) {
                memcpy(&outputData[i * width * height * 3], outputFrames[i].data.data(), width * height * 3);
            }
            
            return success;
            
        } catch (const std::exception& e) {
            LOGE("Batch processing failed: %s", e.what());
            return false;
        }
    }
    
    // One-way processing methods (send data to FinalOutputCollector)
    bool processFrameOneWay(uint8_t* inputData, int width, int height) {
        std::lock_guard<std::mutex> lock(engineMutex_);
        
        if (!initialized_) {
            LOGE("Engine not initialized for one-way frame processing");
            return false;
        }
        
        try {
            LOGI("Processing frame one-way: %dx%d", width, height);
            
            // Simulate processing time
            auto startTime = std::chrono::high_resolution_clock::now();
            std::this_thread::sleep_for(std::chrono::milliseconds(5));
            
            // Create processed frame data
            std::vector<uint8_t> processedData(inputData, inputData + (width * height * 3));
            
            auto endTime = std::chrono::high_resolution_clock::now();
            double processingTime = std::chrono::duration<double, std::chrono::milliseconds::period>(
                endTime - startTime).count();
            
            // Send to AI3_Sender (redirected output)
            AI3_Sender sender;
            sender.storeData("AI3 Processed Frame Data");
            
            return true;
            
        } catch (const std::exception& e) {
            LOGE("One-way frame processing failed: %s", e.what());
            return false;
        }
    }
    
    bool processBatchOneWay(uint8_t* inputData, int width, int height, int frameCount) {
        std::lock_guard<std::mutex> lock(engineMutex_);
        
        if (!initialized_) {
            LOGE("Engine not initialized for one-way batch processing");
            return false;
        }
        
        try {
            LOGI("Processing batch one-way: %d frames (%dx%d)", frameCount, width, height);
            
            auto startTime = std::chrono::high_resolution_clock::now();
            
            // Create processed batch data
            ProcessedBatch processedBatch;
            processedBatch.batchId = 0; // Would need to track batch IDs in real implementation
            processedBatch.frameCount = frameCount;
            processedBatch.frames.reserve(frameCount);
            processedBatch.mode = vulkanEnabled_ ? "GPU" : "CPU";
            
            for (int i = 0; i < frameCount; ++i) {
                // Simulate processing each frame
                std::this_thread::sleep_for(std::chrono::milliseconds(2));
                
                ProcessedFrame frame;
                frame.frameId = i;
                frame.width = width;
                frame.height = height;
                frame.channels = 3;
                frame.processingTime = 10.0; // Simulated
                frame.mode = processedBatch.mode;
                
                // Copy frame data from input
                size_t frameSize = width * height * 3;
                frame.data.assign(&inputData[i * frameSize], &inputData[(i + 1) * frameSize]);
                
                processedBatch.frames.push_back(std::move(frame));
            }
            
            auto endTime = std::chrono::high_resolution_clock::now();
            processedBatch.totalProcessingTime = std::chrono::duration<double, std::chrono::milliseconds::period>(
                endTime - startTime).count();
            processedBatch.avgFps = frameCount / (processedBatch.totalProcessingTime / 1000.0);
            
            // Send to AI3_Sender (redirected output)
            AI3_Sender sender;
            sender.storeData("AI3 Processed Batch Data");
            
            return true;
            
        } catch (const std::exception& e) {
            LOGE("One-way batch processing failed: %s", e.what());
            return false;
        }
    }
    
    void setPerformanceMode(int mode) {
                LOGI("Setting performance mode to QUALITY");
                // Configure for highest quality
                break;
            case 1:
                LOGI("Setting performance mode to BALANCED");
                // Configure for balanced performance
                break;
            case 2:
                LOGI("Setting performance mode to PERFORMANCE");
                // Configure for maximum speed
                break;
        }
    }
    
    bool isVulkanEnabled() const {
        return vulkanEnabled_;
    }
    
    ChunkStats getStatistics() const {
        if (chunkManager_) {
            return chunkManager_->getStatistics();
        }
        return ChunkStats();
    }
    
    void shutdown() {
        std::lock_guard<std::mutex> lock(engineMutex_);
        
        LOGI("Shutting down Kronop Engine");
        
        if (deblurEngine_) {
            deblurEngine_->shutdown();
            deblurEngine_.reset();
        }
        
        if (chunkManager_) {
            chunkManager_.reset();
        }
        
        if (vulkanContext_) {
            vulkanContext_->shutdown();
            vulkanContext_.reset();
        }
        
        initialized_ = false;
        vulkanEnabled_ = false;
    }
};

// Global engine instance
static std::unique_ptr<KronopEngine> g_kronopEngine;
static std::mutex g_engineMutex;

} // namespace kronop

// JNI Functions
extern "C" {

JNIEXPORT jboolean JNICALL
Java_com_kronop_KronopNativeInterface_initialize(JNIEnv* env, jobject thiz, 
                                                  jint width, jint height, jboolean enableVulkan) {
    std::lock_guard<std::mutex> lock(g_engineMutex);
    
    if (!g_kronopEngine) {
        g_kronopEngine = std::make_unique<kronop::KronopEngine>();
    }
    
    bool success = g_kronopEngine->initialize(width, height, enableVulkan);
    LOGI("Native initialization %s", success ? "successful" : "failed");
    return success;
}

JNIEXPORT jboolean JNICALL
Java_com_kronop_KronopNativeInterface_processFrame(JNIEnv* env, jobject thiz,
                                                    jbyteArray inputArray,
                                                    jint width, jint height) {
    if (!g_kronopEngine) {
        LOGE("Engine not initialized");
        return JNI_FALSE;
    }
    
    jbyte* inputPtr = env->GetByteArrayElements(inputArray, nullptr);
    
    if (!inputPtr) {
        LOGE("Failed to get input array elements");
        return JNI_FALSE;
    }
    
    // One-way processing - data goes to FinalOutputCollector
    bool success = g_kronopEngine->processFrameOneWay(
        reinterpret_cast<uint8_t*>(inputPtr),
        width, height
    );
    
    env->ReleaseByteArrayElements(inputArray, inputPtr, JNI_ABORT);
    
    return success;
}

JNIEXPORT jboolean JNICALL
Java_com_kronop_KronopNativeInterface_processBatch(JNIEnv* env, jobject thiz,
                                                  jbyteArray inputArray,
                                                  jint width, jint height, jint frameCount) {
    if (!g_kronopEngine) {
        LOGE("Engine not initialized");
        return JNI_FALSE;
    }
    
    jbyte* inputPtr = env->GetByteArrayElements(inputArray, nullptr);
    
    if (!inputPtr) {
        LOGE("Failed to get batch input array elements");
        return JNI_FALSE;
    }
    
    // One-way processing - data goes to FinalOutputCollector
    bool success = g_kronopEngine->processBatchOneWay(
        reinterpret_cast<uint8_t*>(inputPtr),
        width, height, frameCount
    );
    
    env->ReleaseByteArrayElements(inputArray, inputPtr, JNI_ABORT);
    
    return success;
}

JNIEXPORT void JNICALL
Java_com_kronop_KronopNativeInterface_setPerformanceMode(JNIEnv* env, jobject thiz, jint mode) {
    if (g_kronopEngine) {
        g_kronopEngine->setPerformanceMode(mode);
    }
}

JNIEXPORT jboolean JNICALL
Java_com_kronop_KronopNativeInterface_isVulkanEnabled(JNIEnv* env, jobject thiz) {
    if (g_kronopEngine) {
        return g_kronopEngine->isVulkanEnabled();
    }
    return JNI_FALSE;
}

JNIEXPORT jstring JNICALL
Java_com_kronop_KronopNativeInterface_getStatistics(JNIEnv* env, jobject thiz) {
    if (!g_kronopEngine) {
        return env->NewStringUTF("Engine not initialized");
    }
    
    kronop::ChunkStats stats = g_kronopEngine->getStatistics();
    
    char statsStr[512];
    snprintf(statsStr, sizeof(statsStr),
        "Processed Chunks: %d\n"
        "Processed Tiles: %d\n"
        "Current Memory: %zu MB\n"
        "Peak Memory: %zu MB\n"
        "Processing FPS: %.2f",
        stats.processedChunks,
        stats.processedTiles,
        stats.currentMemoryUsage / (1024 * 1024),
        stats.peakMemoryUsage / (1024 * 1024),
        stats.processingFPS
    );
    
    return env->NewStringUTF(statsStr);
}

JNIEXPORT void JNICALL
Java_com_kronop_KronopNativeInterface_shutdown(JNIEnv* env, jobject thiz) {
    std::lock_guard<std::mutex> lock(g_engineMutex);
    
    if (g_kronopEngine) {
        g_kronopEngine->shutdown();
        g_kronopEngine.reset();
    }
    
    LOGI("Native interface shutdown complete");
}

// JNI_OnLoad - Called when library is loaded
JNIEXPORT jint JNICALL JNI_OnLoad(JavaVM* vm, void* reserved) {
    LOGI("Kronop Native Library loaded");
    
    JNIEnv* env;
    if (vm->GetEnv(reinterpret_cast<void**>(&env), JNI_VERSION_1_6) != JNI_OK) {
        return JNI_ERR;
    }
    
    // Register native methods if needed
    return JNI_VERSION_1_6;
}

// JNI_OnUnload - Called when library is unloaded
JNIEXPORT void JNICALL JNI_OnUnload(JavaVM* vm, void* reserved) {
    LOGI("Kronop Native Library unloaded");
    
    std::lock_guard<std::mutex> lock(g_engineMutex);
    if (g_kronopEngine) {
        g_kronopEngine->shutdown();
        g_kronopEngine.reset();
    }
}

} // extern "C"
