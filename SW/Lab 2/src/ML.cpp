#include <iostream>
#include <sstream>
#include <vector>

#include "Config.h"
#include "Model.h"
#include "Types.h"
#include "Utils.h"
#include "layers/Convolutional.h"
#include "layers/Dense.h"
#include "layers/Flatten.h"
#include "layers/Layer.h"
#include "layers/MaxPooling.h"
#include "layers/Softmax.h"

#define QUANTIZE 8

#define METHOD 2

#if METHOD == 0
#define COMPUTEMETHOD NAIVE
#elif METHOD == 1
#define COMPUTEMETHOD QUANTIZED
#elif METHOD == 2
#define COMPUTEMETHOD ACCEL
#endif


#ifdef ZEDBOARD
#include <file_transfer/file_transfer.h>
#endif

namespace ML {

// Build our ML toy model
Model buildToyModel(const Path modelPath) {
    Model model;
    logInfo("--- Building Toy Model ---");

    // --- Conv 1: L1 ---
    // Input shape: 64x64x3
    // Output shape: 60x60x32
    model.addLayer<ConvolutionalLayer>(
        LayerParams{sizeof(fp32), {64, 64, 3}},                                    // Input Data
        LayerParams{sizeof(fp32), {60, 60, 32}},                                   // Output Data
        LayerParams{sizeof(fp32), {5, 5, 3, 32}, modelPath / "conv1_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {32}, modelPath / "conv1_biases.bin"}            // Bias
    );

    // --- Conv 2: L2 ---
    // Input shape: 60x60x32
    // Output shape: 56x56x32
    model.addLayer<ConvolutionalLayer>(
        LayerParams{sizeof(fp32), {60, 60, 32}},                                   // Input Data
        LayerParams{sizeof(fp32), {56, 56, 32}},                                   // Output Data
        LayerParams{sizeof(fp32), {5, 5, 32, 32}, modelPath / "conv2_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {32}, modelPath / "conv2_biases.bin"}            // Bias
    );

    // --- MPL 1: L3 ---
    // Input shape: 56x56x32
    // Output shape: 28x28x32
    model.addLayer<MaxPoolingLayer>(
        LayerParams{sizeof(fp32), {56, 56, 32}},                                   // Input Data
        LayerParams{sizeof(fp32), {28, 28, 32}},                                   // Output Data
        LayerParams{sizeof(fp32), {2, 2}}                                          // Pool size
    );

    // --- Conv 3: L4 ---
    // Input shape: 28x28x32
    // Output shape: 26x26x64
    model.addLayer<ConvolutionalLayer>(
        LayerParams{sizeof(fp32), {28, 28, 32}},                                   // Input Data
        LayerParams{sizeof(fp32), {26, 26, 64}},                                   // Output Data
        LayerParams{sizeof(fp32), {3, 3, 32, 64}, modelPath / "conv3_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {64}, modelPath / "conv3_biases.bin"}            // Bias
    );

    // --- Conv 4: L5 ---
    // Input shape: 26x26x64
    // Output shape: 24x24x64
    model.addLayer<ConvolutionalLayer>(
        LayerParams{sizeof(fp32), {26, 26, 64}},                                   // Input Data
        LayerParams{sizeof(fp32), {24, 24, 64}},                                   // Output Data
        LayerParams{sizeof(fp32), {3, 3, 64, 64}, modelPath / "conv4_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {64}, modelPath / "conv4_biases.bin"}            // Bias
    );

    // --- MPL 2: L6 ---
    // Input shape: 24x24x64
    // Output shape: 12x12x64
    model.addLayer<MaxPoolingLayer>(
        LayerParams{sizeof(fp32), {24, 24, 64}},                                   // Input Data
        LayerParams{sizeof(fp32), {12, 12, 64}},                                   // Output Data
        LayerParams{sizeof(fp32), {2, 2}}                                          // Pool size
    );

    // --- Conv 5: L7 ---
    // Input shape: 12x12x64
    // Output shape: 10x10x64
    model.addLayer<ConvolutionalLayer>(
        LayerParams{sizeof(fp32), {12, 12, 64}},                                   // Input Data
        LayerParams{sizeof(fp32), {10, 10, 64}},                                   // Output Data
        LayerParams{sizeof(fp32), {3, 3, 64, 64}, modelPath / "conv5_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {64}, modelPath / "conv5_biases.bin"}            // Bias
    );

    // --- Conv 6: L8 ---
    // Input shape: 10x10x64
    // Output shape: 8x8x128
    model.addLayer<ConvolutionalLayer>(
        LayerParams{sizeof(fp32), {10, 10, 64}},                                   // Input Data
        LayerParams{sizeof(fp32), {8, 8, 128}},                                    // Output Data
        LayerParams{sizeof(fp32), {3, 3, 64, 128}, modelPath / "conv6_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {128}, modelPath / "conv6_biases.bin"}           // Bias
    );

    // --- MPL 3: L9 ---
    // Input shape: 8x8x128
    // Output shape: 4x4x128
    model.addLayer<MaxPoolingLayer>(
        LayerParams{sizeof(fp32), {8, 8, 128}},                                    // Input Data
        LayerParams{sizeof(fp32), {4, 4, 128}},                                    // Output Data
        LayerParams{sizeof(fp32), {2, 2}}                                          // Pool size
    );

    // --- Flatten: L10 ---
    // Input shape: 4x4x128 = 2048
    // Output shape: 2048 (flattened)
    model.addLayer<FlattenLayer>(
        LayerParams{sizeof(fp32), {4, 4, 128}},                                    // Input Data (4D)
        LayerParams{sizeof(fp32), {2048}}                                          // Output Data (1D flattened)
    );

    // --- Dense 1: L11 ---
    // Input shape: 2048
    // Output shape: 256
    model.addLayer<DenseLayer>(
        LayerParams{sizeof(fp32), {2048}},                                         // Input Data (flattened)
        LayerParams{sizeof(fp32), {256}},                                          // Output Data
        LayerParams{sizeof(fp32), {2048, 256}, modelPath / "dense1_weights.bin"}, // Weights
        LayerParams{sizeof(fp32), {256}, modelPath / "dense1_biases.bin"}         // Bias
    );

    // --- Dense 2: L12 ---
    // Input shape: 256
    // Output shape: 200
    model.addLayer<DenseLayer>(
        LayerParams{sizeof(fp32), {256}},                                          // Input Data
        LayerParams{sizeof(fp32), {200}},                                          // Output Data
        LayerParams{sizeof(fp32), {256, 200}, modelPath / "dense2_weights.bin"},  // Weights
        LayerParams{sizeof(fp32), {200}, modelPath / "dense2_biases.bin"}         // Bias
    );

    // --- Softmax 1: L13 ---
    // Input shape: 200
    // Output shape: 200
    model.addLayer<SoftmaxLayer>(
        LayerParams{sizeof(fp32), {200}},                                          // Input Data
        LayerParams{sizeof(fp32), {200}}                                           // Output Data
    );

    return model;
}

void runBasicTest(const Model& model, const Path& basePath) {
    logInfo("--- Running Basic Test ---");

    // Load an image
    LayerData img = {{sizeof(fp32), {64, 64, 3}, "./data/image_0.bin"}};
    img.loadData();

    // Compare images
    std::cout << "Comparing image 0 to itself (max error): " << img.compare<fp32>(img) << std::endl
              << "Comparing image 0 to itself (T/F within epsilon " << ML::Config::EPSILON << "): " << std::boolalpha
              << img.compareWithin<fp32>(img, ML::Config::EPSILON) << std::endl;

    // Test again with a modified copy
    std::cout << "\nChange a value by 0.1 and compare again" << std::endl;
    
    LayerData imgCopy = img;
    imgCopy.get<fp32>(0) += 0.1;

    // Compare images
    img.compareWithinPrint<fp32>(imgCopy);

    // Test again with a modified copy
    log("Change a value by 0.1 and compare again...");
    imgCopy.get<fp32>(0) += 0.1;

    // Compare Images
    img.compareWithinPrint<fp32>(imgCopy);
}

void runLayerTest(const std::size_t layerNum, const Model& model, const Path& basePath) {
    logInfo(std::string("--- Running Layer Test ") + std::to_string(layerNum) + "---");
    
    try {
        // For layer testing, we always start with the original input image
        // and run inference up to the specified layer
        LayerData img({sizeof(fp32), {64, 64, 3}, basePath / "image_0.bin"});
        img.loadData();

        Timer timer("Layer Inference");

        // Run inference on the model up to the specified layer
        timer.start();
        
        // Start with layer 0
        model.inferenceLayer(img, 0, Layer::InfType::NAIVE);
        const LayerData* output = &model[0].getOutputData();
        
        // Run subsequent layers up to layerNum
        for (std::size_t i = 1; i <= layerNum; i++) {
            model.inferenceLayer(*output, i, Layer::InfType::NAIVE);
            output = &model[i].getOutputData();
        }
        
        timer.stop();

        // Debug: Print the output dimensions first
        std::cout << "Layer " << layerNum << " output dimensions: ";
        for (size_t dim : output->getParams().dims) {
            std::cout << dim << " ";
        }
        std::cout << "(total: " << output->getParams().flat_count() << " elements)" << std::endl;

        // Load the expected output for this specific layer
        std::string expectedFileName = "layer_" + std::to_string(layerNum) + "_output.bin";
        Path expectedPath = basePath / "image_0_data" / expectedFileName.c_str();
        
        // Debug output dimensions BEFORE creating LayerData expected
        std::cout << "Output dimensions: ";
        for (size_t dim : output->getParams().dims) {
            std::cout << dim << " ";
        }
        std::cout << "(total: " << output->getParams().flat_count() << " elements)" << std::endl;
        
        // Check expected file size to infer correct dimensions
        std::ifstream file(expectedPath, std::ios::binary | std::ios::ate);
        if (file.is_open()) {
            std::streamsize size = file.tellg();
            std::cout << "Expected file size: " << size << " bytes (" << size/4 << " elements)" << std::endl;
            file.close();
            
            // Calculate expected elements
            size_t expectedElements = size / 4;
            size_t outputElements = output->getParams().flat_count();
            
            if (expectedElements != outputElements) {
                std::cout << "DIMENSION MISMATCH: Output has " << outputElements << " elements, expected " << expectedElements << std::endl;
                return; // Skip this test
            }
        }
        
        // Create LayerData for comparison
        LayerData expected(output->getParams(), expectedPath);
        
        // Handle dimension mismatch for dense layers by creating a compatible comparison
        if (layerNum >= 9) {
            std::cout << "DENSE LAYER DETECTED: Attempting flexible comparison..." << std::endl;
            // For dense layers, try to load with matching element count
            std::ifstream file(expectedPath, std::ios::binary | std::ios::ate);
            if (file.is_open()) {
                std::streamsize size = file.tellg();
                file.close();
                size_t expectedElements = size / 4;
                size_t outputElements = output->getParams().flat_count();
                
                if (expectedElements == outputElements) {
                    std::cout << "Element counts match (" << expectedElements << "), comparing raw data..." << std::endl;
                    // Both have same element count, can compare raw data
                    std::vector<fp32> expectedData(expectedElements);
                    std::ifstream dataFile(expectedPath, std::ios::binary);
                    dataFile.read(reinterpret_cast<char*>(expectedData.data()), size);
                    dataFile.close();
                    
                    const fp32* outputRaw = static_cast<const fp32*>(output->raw());
                    
                    // Calculate cosine similarity manually
                    double dotProduct = 0.0, normA = 0.0, normB = 0.0;
                    for (size_t i = 0; i < expectedElements; ++i) {
                        dotProduct += outputRaw[i] * expectedData[i];
                        normA += outputRaw[i] * outputRaw[i];
                        normB += expectedData[i] * expectedData[i];
                    }
                    double similarity = dotProduct / (std::sqrt(normA) * std::sqrt(normB));
                    std::cout << "Manual Cosine Similarity: " << (similarity * 100.0) << "% (" << similarity << ")" << std::endl;
                    return;
                } else {
                    std::cout << "Element count mismatch: output=" << outputElements << ", expected=" << expectedElements << std::endl;
                    return;
                }
            }
        }
        
        expected.loadData();
        
        // Compare the outputs
        output->compareWithinPrint<fp32>(expected);
    } catch (const std::exception& e) {
        std::cout << "Layer " << layerNum << " test failed: " << e.what() << std::endl;
    }
}

void runInferenceTest(const Model& model, const Path& basePath) {
    logInfo("--- Running Inference Test ---");

    // Load the input image
    LayerData img(model[0].getInputParams(), basePath / "image_0.bin");
    img.loadData();

    Timer timer("Full Inference");

    // Run full inference on the model
    timer.start();
    const LayerData& output = model.inference(img, Layer::InfType::NAIVE);
    timer.stop();

    // Compare against the final layer output (layer 11 for our 12-layer model, 0-indexed)
    // The model has 13 layers (0-12), so the final output should be layer_11_output.bin
    try {
        LayerData expected(model.getOutputLayer().getOutputParams(), basePath / "image_0_data" / "layer_11_output.bin");
        expected.loadData();
        output.compareWithinPrint<fp32>(expected);
    } catch (const std::exception& e) {
        std::cout << "Full inference test failed: " << e.what() << std::endl;
        std::cout << "Note: Expected final layer output file may not exist." << std::endl;
    }
}

void runQuantizedInferenceTest(const Model& model, const Path& basePath) {
    logInfo("--- Running QUANTIZED Inference Test ---");

    // Load the input image
    LayerData img(model[0].getInputParams(), basePath / "image_0.bin");
    img.loadData();

    Timer timer("Quantized Full Inference");

    // Run full inference on the model using QUANTIZED mode
    timer.start();
    const LayerData& output = model.inference(img, Layer::InfType::QUANTIZED);
    timer.stop();

    // Compare against the final layer output (layer 11 for our 12-layer model, 0-indexed)
    try {
        LayerData expected(model.getOutputLayer().getOutputParams(), basePath / "image_0_data" / "layer_11_output.bin");
        expected.loadData();
        std::cout << "QUANTIZED vs EXPECTED: ";
        output.compareWithinPrint<fp32>(expected);
    } catch (const std::exception& e) {
        std::cout << "Quantized inference test failed: " << e.what() << std::endl;
    }
    
    // Also compare quantized vs naive to see the difference
    const LayerData& naiveOutput = model.inference(img, Layer::InfType::NAIVE);
    std::cout << "QUANTIZED vs NAIVE: ";
    output.compareWithinPrint<fp32>(naiveOutput);
}

void runAllLayerTests(const Model& model, const Path& basePath) {
    logInfo("--- Running All Layer Tests ---");
    
    // Test all layers to see complete verification results
    for (std::size_t layerNum = 0; layerNum <= 11; ++layerNum) {
        runLayerTest(layerNum, model, basePath);
    }
}

void runTests() {
    // Base input data path (determined from current directory of where you are running the command)
    Path basePath("data");  // May need to be altered for zedboards loading from SD Cards

    // Build the model and allocate the buffers
    Model model = buildToyModel(basePath / "model");
    model.allocLayers();

    // Run some framework tests as an example of loading data
    runBasicTest(model, basePath);

    // Run all layer tests to verify tensor shapes
    runAllLayerTests(model, basePath);

    // Run all layer tests (uncomment the line below to test all layers 0-11)
    // runAllLayerTests(model, basePath);

    // Run an end-to-end inference test
    runInferenceTest(model, basePath);
    
    // Run quantized inference test
    runQuantizedInferenceTest(model, basePath);

    // Clean up
    model.freeLayers();
    std::cout << "\n\n----- ML::runTests() COMPLETE -----\n";
}

} // namespace ML

#ifdef ZEDBOARD
extern "C"
int main() {
    try {
        static FATFS fatfs;
        if (f_mount(&fatfs, "/", 1) != FR_OK) {
            throw std::runtime_error("Failed to mount SD card. Is it plugged in?");
        }
        ML::runTests();
    } catch (const std::exception& e) {
        std::cerr << "\n\n----- EXCEPTION THROWN -----\n" << e.what() << '\n';
    }
    std::cout << "\n\n----- STARTING FILE TRANSFER SERVER -----\n";
    FileServer::start_file_transfer_server();
}
#else
int main() {
    ML::runTests();
}
#endif