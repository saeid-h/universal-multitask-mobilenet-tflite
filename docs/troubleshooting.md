# Troubleshooting

Common issues and their solutions.

## Model Creation Errors

### "Pretrained weights only available for alpha 0.75 or 1.0"

**Problem**: You're trying to use `--use-pretrained` with alpha 0.25 or 0.50.

**Solution**: Either:
- Remove `--use-pretrained` flag
- Change to `--alpha 0.75` or `--alpha 1.0`

Alpha 0.25 and 0.50 don't have pretrained weights in Keras MobileNet V3.

### "Invalid input shape format"

**Problem**: The input shape string format is incorrect.

**Solution**: Use format `HxWxC` exactly, like:
- `"224x224x3"` (correct)
- `"224,224,3"` (wrong - use x not comma)
- `224x224x3` (wrong - needs quotes)

### "Number of head names must match number of heads"

**Problem**: You provided `--head-names` but the count doesn't match `--heads`.

**Solution**: Ensure the number of comma-separated values matches:
```bash
--heads "5,2,3" --head-names "a,b,c"  # Correct: 3 heads, 3 names
--heads "5,2,3" --head-names "a,b"    # Wrong: 3 heads, 2 names
```

### "Each head must have at least 1 class"

**Problem**: One of your head class counts is 0 or negative.

**Solution**: Check your `--heads` argument. All values must be positive integers:
```bash
--heads "5,2,3"  # Correct
--heads "5,0,3"  # Wrong: second head has 0 classes
```

### "Either --heads (for new model) or --keras-model-path (for trained model) must be provided"

**Problem**: You didn't provide either `--heads` or `--keras-model-path`.

**Solution**: 
- To create a new model: Provide `--heads "5,2,3"`
- To quantize a trained model: Provide `--keras-model-path ./model.keras`

You need at least one of these arguments.

### "Model file not found" or "Failed to load model"

**Problem**: Cannot load a trained model file.

**Solution**:
- Verify the file path is correct and the file exists
- Ensure the file is a valid Keras model (.keras format)
- Try loading it manually: `tf.keras.models.load_model(path, compile=False)`
- Check file permissions

## Quantization Issues

### Model not fully quantized

**Problem**: The quantization info shows float32 tensors present.

**Possible causes**:
- Some operations can't be quantized (rare with MobileNet V3)
- Calibration dataset issues
- Model complexity

**Solution**:
- Check the quantization_info.json to see which tensors are float
- Try increasing calibration samples
- This is usually not a problem unless you see significant accuracy loss

### Large model size after quantization

**Problem**: Model is larger than expected after quantization.

**Possible causes**:
- Using alpha 1.0 (largest model)
- Many heads with many classes
- Quantization overhead

**Solution**:
- Use smaller alpha (0.25 or 0.50)
- Reduce number of classes per head if possible
- Check if you're saving the Keras model too (use `--no-save-keras`)

### Poor quantization quality

**Problem**: Accuracy drops significantly after quantization.

**Solution**:
- Increase `--calibration-samples` to 200-300
- Try a larger alpha for more model capacity
- Verify your calibration data is representative of real usage

## Performance Issues

### Model creation takes too long

**Problem**: Script runs slowly.

**Possible causes**:
- Large number of calibration samples
- Large model size (high alpha)
- System resources

**Solution**:
- Reduce `--calibration-samples` (100 is usually enough)
- Use smaller alpha if acceptable
- Ensure you have adequate RAM and CPU

### Model inference is slow

**Problem**: The generated TFLite model runs slowly.

**Possible causes**:
- Large input size
- Large alpha value
- Hardware limitations

**Solution**:
- Use smaller input size (e.g., 128x128 instead of 224x224)
- Use smaller alpha (0.25 instead of 1.0)
- Check if your hardware supports uint8/int8 acceleration (including Vela compiler for Arm Ethos-U NPU)
- Consider using hardware-specific optimizations for your target device

## File and Path Issues

### "Output directory cannot be created"

**Problem**: Permission error or invalid path.

**Solution**:
- Check write permissions in the target directory
- Use an absolute path or ensure relative path is correct
- Create the directory manually first if needed

### Cannot import models package

**Problem**: Python can't find the models module.

**Solution**:
- Run the script from the repository root directory: `python src/create_quantized_mobilenet_v3.py`
- Ensure you're using the correct Python environment
- Check that the models package exists in the expected location
- Verify you're in the project root when running scripts

## Accuracy Issues

### Model accuracy lower than expected

**Problem**: After quantization, accuracy drops too much.

**Possible causes**:
- Alpha too small for the task complexity
- Input preprocessing mismatch
- Quantization calibration issues

**Solution**:
- Try larger alpha (0.5 or 0.75)
- Verify input preprocessing matches training
- Increase calibration samples
- Check if pretrained weights would help (if using alpha 0.75+)

### Outputs don't make sense

**Problem**: Model outputs unexpected values.

**Possible causes**:
- Incorrect head configuration
- Output quantization not handled correctly
- Model not properly trained (this tool creates untrained models)

**Solution**:
- Verify head class counts match your expectations
- Check output quantization parameters and convert properly (models output logits, apply softmax in post-processing)
- Remember: This tool creates model architecture, not trained models. You need to train the model separately.
- Note: Models default to Vela-compatible mode (logits output). Apply softmax when interpreting outputs.

## Vela Compilation Issues

### "ValueError: negative shift count" during Vela compilation

**Problem**: Model fails to compile with Vela compiler, showing a negative shift count error in softmax operations.

**Cause**: This error occurs when models contain quantized softmax layers with quantization parameters that are incompatible with Vela's graph optimization.

**Solution**: 
- Models are generated Vela-compatible by default (outputs logits, no softmax)
- If you see this error, regenerate the model with the latest tool version
- The default behavior (logits output) avoids this issue
- Apply softmax in post-processing when interpreting outputs

### Model outputs logits instead of probabilities

**Problem**: Model outputs seem wrong or need conversion.

**Explanation**: This is expected and correct. Models default to Vela-compatible mode, which means:
- Outputs are logits (not probabilities)
- Softmax must be applied in post-processing
- This ensures compatibility with Vela compiler and Arm Ethos-U NPU

**Solution**: 
- Convert quantized outputs to float: `logits = (uint8_value - zero_point) * scale`
- Apply softmax: `probabilities = softmax(logits)`
- If you specifically need softmax in the model (non-Vela deployment), use `--with-softmax` flag

### Unified output not working

**Problem**: `--unified-output` flag doesn't create unified output.

**Possible causes**:
- Single-head model (unified output only applies to multi-head models)
- Loading a trained model (unified output only available for newly created models)

**Solution**:
- Unified output is automatically ignored for single-head models (not needed)
- Unified output is only available when creating new models, not when loading trained models with `--keras-model-path`
- Check the model report to see if unified output was created (look for `unified_output` section in JSON report)

### How to access unified output in inference

**Problem**: Need to know how to extract predictions from unified output.

**Solution**:
- The unified output contains all head outputs concatenated in order
- Head order is documented in the model report (`unified_output.head_order`)
- Example: For heads [5, 2, 3], unified output shape is [batch, 10]
  - First 5 values: head_1 predictions
  - Next 2 values: head_2 predictions  
  - Last 3 values: head_3 predictions
- Individual head outputs are still available for training

## Getting Help

If you encounter issues not covered here:

1. Check the error message carefully - it usually points to the problem
2. Review the model summary and report files for clues
3. Try a simpler configuration first (single head, default alpha)
4. Verify your Python and TensorFlow versions are compatible
5. Check that you have sufficient disk space for outputs
