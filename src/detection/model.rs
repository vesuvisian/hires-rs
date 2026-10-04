#![allow(clippy::all)]
#![allow(dead_code, unused_imports, unused_variables)]
// Generated from ONNX by burn-onnx — do not hand-edit.

extern crate alloc;
use burn::nn::PaddingConfig2d;
use burn::nn::conv::Conv2d;
use burn::nn::conv::Conv2dConfig;
use burn::nn::pool::MaxPool2d;
use burn::nn::pool::MaxPool2dConfig;
use burn::prelude::*;
use burn::tensor::Bytes;
use burn_store::BurnpackStore;
use burn_store::ModuleSnapshot;

#[derive(Module, Debug)]
pub struct Submodule1 {
    conv2d1: Conv2d,
    conv2d2: Conv2d,
    conv2d3: Conv2d,
    conv2d4: Conv2d,
    conv2d5: Conv2d,
    conv2d6: Conv2d,
    conv2d7: Conv2d,
    conv2d8: Conv2d,
    conv2d9: Conv2d,
    conv2d10: Conv2d,
    conv2d11: Conv2d,
    conv2d12: Conv2d,
    conv2d13: Conv2d,
    conv2d14: Conv2d,
    conv2d15: Conv2d,
    conv2d16: Conv2d,
    conv2d17: Conv2d,
    conv2d18: Conv2d,
    conv2d19: Conv2d,
    #[module(skip)]
    device: Device,
}
impl Submodule1 {
    #[allow(unused_variables)]
    pub fn new(device: &Device) -> Self {
        let conv2d1 = Conv2dConfig::new([3, 16], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d2 = Conv2dConfig::new([16, 32], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d3 = Conv2dConfig::new([32, 32], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d4 = Conv2dConfig::new([16, 16], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d5 = Conv2dConfig::new([16, 16], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d6 = Conv2dConfig::new([48, 32], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d7 = Conv2dConfig::new([32, 64], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d8 = Conv2dConfig::new([64, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d9 = Conv2dConfig::new([32, 32], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d10 = Conv2dConfig::new([32, 32], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d11 = Conv2dConfig::new([32, 32], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d12 = Conv2dConfig::new([32, 32], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d13 = Conv2dConfig::new([128, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d14 = Conv2dConfig::new([64, 128], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d15 = Conv2dConfig::new([128, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d16 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d17 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d18 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d19 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        Self {
            conv2d1,
            conv2d2,
            conv2d3,
            conv2d4,
            conv2d5,
            conv2d6,
            conv2d7,
            conv2d8,
            conv2d9,
            conv2d10,
            conv2d11,
            conv2d12,
            conv2d13,
            conv2d14,
            conv2d15,
            conv2d16,
            conv2d17,
            conv2d18,
            conv2d19,
            device: device.clone(),
        }
    }
    #[allow(clippy::let_and_return, clippy::approx_constant)]
    pub fn forward(&self, images: Tensor<4>) -> (Tensor<4>, Tensor<4>) {
        let conv2d1_out1 = self.conv2d1.forward(images);
        let sigmoid1_out1 = burn::tensor::activation::sigmoid(conv2d1_out1.clone());
        let mul1_out1 = conv2d1_out1.mul(sigmoid1_out1);
        let conv2d2_out1 = self.conv2d2.forward(mul1_out1);
        let sigmoid2_out1 = burn::tensor::activation::sigmoid(conv2d2_out1.clone());
        let mul2_out1 = conv2d2_out1.mul(sigmoid2_out1);
        let conv2d3_out1 = self.conv2d3.forward(mul2_out1);
        let sigmoid3_out1 = burn::tensor::activation::sigmoid(conv2d3_out1.clone());
        let mul3_out1 = conv2d3_out1.mul(sigmoid3_out1);
        let split_tensors = mul3_out1.split_with_sizes([16, 16].into(), 1);
        let [split1_out1, split1_out2] = split_tensors.try_into().unwrap();
        let conv2d4_out1 = self.conv2d4.forward(split1_out2.clone());
        let sigmoid4_out1 = burn::tensor::activation::sigmoid(conv2d4_out1.clone());
        let mul4_out1 = conv2d4_out1.mul(sigmoid4_out1);
        let conv2d5_out1 = self.conv2d5.forward(mul4_out1);
        let sigmoid5_out1 = burn::tensor::activation::sigmoid(conv2d5_out1.clone());
        let mul5_out1 = conv2d5_out1.mul(sigmoid5_out1);
        let add1_out1 = split1_out2.clone().add(mul5_out1);
        let concat1_out1 =
            burn::tensor::Tensor::cat([split1_out1, split1_out2, add1_out1].into(), 1);
        let conv2d6_out1 = self.conv2d6.forward(concat1_out1);
        let sigmoid6_out1 = burn::tensor::activation::sigmoid(conv2d6_out1.clone());
        let mul6_out1 = conv2d6_out1.mul(sigmoid6_out1);
        let conv2d7_out1 = self.conv2d7.forward(mul6_out1);
        let sigmoid7_out1 = burn::tensor::activation::sigmoid(conv2d7_out1.clone());
        let mul7_out1 = conv2d7_out1.mul(sigmoid7_out1);
        let conv2d8_out1 = self.conv2d8.forward(mul7_out1);
        let sigmoid8_out1 = burn::tensor::activation::sigmoid(conv2d8_out1.clone());
        let mul8_out1 = conv2d8_out1.mul(sigmoid8_out1);
        let split_tensors = mul8_out1.split_with_sizes([32, 32].into(), 1);
        let [split2_out1, split2_out2] = split_tensors.try_into().unwrap();
        let conv2d9_out1 = self.conv2d9.forward(split2_out2.clone());
        let sigmoid9_out1 = burn::tensor::activation::sigmoid(conv2d9_out1.clone());
        let mul9_out1 = conv2d9_out1.mul(sigmoid9_out1);
        let conv2d10_out1 = self.conv2d10.forward(mul9_out1);
        let sigmoid10_out1 = burn::tensor::activation::sigmoid(conv2d10_out1.clone());
        let mul10_out1 = conv2d10_out1.mul(sigmoid10_out1);
        let add2_out1 = split2_out2.clone().add(mul10_out1);
        let conv2d11_out1 = self.conv2d11.forward(add2_out1.clone());
        let sigmoid11_out1 = burn::tensor::activation::sigmoid(conv2d11_out1.clone());
        let mul11_out1 = conv2d11_out1.mul(sigmoid11_out1);
        let conv2d12_out1 = self.conv2d12.forward(mul11_out1);
        let sigmoid12_out1 = burn::tensor::activation::sigmoid(conv2d12_out1.clone());
        let mul12_out1 = conv2d12_out1.mul(sigmoid12_out1);
        let add3_out1 = add2_out1.clone().add(mul12_out1);
        let concat2_out1 =
            burn::tensor::Tensor::cat([split2_out1, split2_out2, add2_out1, add3_out1].into(), 1);
        let conv2d13_out1 = self.conv2d13.forward(concat2_out1);
        let sigmoid13_out1 = burn::tensor::activation::sigmoid(conv2d13_out1.clone());
        let mul13_out1 = conv2d13_out1.mul(sigmoid13_out1);
        let conv2d14_out1 = self.conv2d14.forward(mul13_out1.clone());
        let sigmoid14_out1 = burn::tensor::activation::sigmoid(conv2d14_out1.clone());
        let mul14_out1 = conv2d14_out1.mul(sigmoid14_out1);
        let conv2d15_out1 = self.conv2d15.forward(mul14_out1);
        let sigmoid15_out1 = burn::tensor::activation::sigmoid(conv2d15_out1.clone());
        let mul15_out1 = conv2d15_out1.mul(sigmoid15_out1);
        let split_tensors = mul15_out1.split_with_sizes([64, 64].into(), 1);
        let [split3_out1, split3_out2] = split_tensors.try_into().unwrap();
        let conv2d16_out1 = self.conv2d16.forward(split3_out2.clone());
        let sigmoid16_out1 = burn::tensor::activation::sigmoid(conv2d16_out1.clone());
        let mul16_out1 = conv2d16_out1.mul(sigmoid16_out1);
        let conv2d17_out1 = self.conv2d17.forward(mul16_out1);
        let sigmoid17_out1 = burn::tensor::activation::sigmoid(conv2d17_out1.clone());
        let mul17_out1 = conv2d17_out1.mul(sigmoid17_out1);
        let add4_out1 = split3_out2.clone().add(mul17_out1);
        let conv2d18_out1 = self.conv2d18.forward(add4_out1.clone());
        let sigmoid18_out1 = burn::tensor::activation::sigmoid(conv2d18_out1.clone());
        let mul18_out1 = conv2d18_out1.mul(sigmoid18_out1);
        let conv2d19_out1 = self.conv2d19.forward(mul18_out1);
        let sigmoid19_out1 = burn::tensor::activation::sigmoid(conv2d19_out1.clone());
        let mul19_out1 = conv2d19_out1.mul(sigmoid19_out1);
        let add5_out1 = add4_out1.clone().add(mul19_out1);
        let concat3_out1 =
            burn::tensor::Tensor::cat([split3_out1, split3_out2, add4_out1, add5_out1].into(), 1);
        (concat3_out1, mul13_out1)
    }
}
#[derive(Module, Debug)]
pub struct Submodule2 {
    conv2d20: Conv2d,
    conv2d21: Conv2d,
    conv2d22: Conv2d,
    conv2d23: Conv2d,
    conv2d24: Conv2d,
    conv2d25: Conv2d,
    conv2d26: Conv2d,
    maxpool2d1: MaxPool2d,
    maxpool2d2: MaxPool2d,
    maxpool2d3: MaxPool2d,
    conv2d27: Conv2d,
    resize1: burn::nn::interpolate::Interpolate2d,
    conv2d28: Conv2d,
    conv2d29: Conv2d,
    conv2d30: Conv2d,
    conv2d31: Conv2d,
    resize2: burn::nn::interpolate::Interpolate2d,
    conv2d32: Conv2d,
    conv2d33: Conv2d,
    conv2d34: Conv2d,
    conv2d35: Conv2d,
    conv2d36: Conv2d,
    conv2d37: Conv2d,
    conv2d38: Conv2d,
    #[module(skip)]
    device: Device,
}
impl Submodule2 {
    #[allow(unused_variables)]
    pub fn new(device: &Device) -> Self {
        let conv2d20 = Conv2dConfig::new([256, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d21 = Conv2dConfig::new([128, 256], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d22 = Conv2dConfig::new([256, 256], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d23 = Conv2dConfig::new([128, 128], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d24 = Conv2dConfig::new([128, 128], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d25 = Conv2dConfig::new([384, 256], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d26 = Conv2dConfig::new([256, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let maxpool2d1 = MaxPool2dConfig::new([5, 5])
            .with_strides([1, 1])
            .with_padding(PaddingConfig2d::Explicit(2, 2, 2, 2))
            .with_dilation([1, 1])
            .with_ceil_mode(false)
            .init();
        let maxpool2d2 = MaxPool2dConfig::new([5, 5])
            .with_strides([1, 1])
            .with_padding(PaddingConfig2d::Explicit(2, 2, 2, 2))
            .with_dilation([1, 1])
            .with_ceil_mode(false)
            .init();
        let maxpool2d3 = MaxPool2dConfig::new([5, 5])
            .with_strides([1, 1])
            .with_padding(PaddingConfig2d::Explicit(2, 2, 2, 2))
            .with_dilation([1, 1])
            .with_ceil_mode(false)
            .init();
        let conv2d27 = Conv2dConfig::new([512, 256], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let resize1 = burn::nn::interpolate::Interpolate2dConfig::new()
            .with_output_size(None)
            .with_scale_factor(Some([2.0, 2.0]))
            .with_mode(burn::nn::interpolate::InterpolateMode::Nearest)
            .with_align_corners(false)
            .init();
        let conv2d28 = Conv2dConfig::new([384, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d29 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d30 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d31 = Conv2dConfig::new([192, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let resize2 = burn::nn::interpolate::Interpolate2dConfig::new()
            .with_output_size(None)
            .with_scale_factor(Some([2.0, 2.0]))
            .with_mode(burn::nn::interpolate::InterpolateMode::Nearest)
            .with_align_corners(false)
            .init();
        let conv2d32 = Conv2dConfig::new([192, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d33 = Conv2dConfig::new([32, 32], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d34 = Conv2dConfig::new([32, 32], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d35 = Conv2dConfig::new([96, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d36 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d37 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d38 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        Self {
            conv2d20,
            conv2d21,
            conv2d22,
            conv2d23,
            conv2d24,
            conv2d25,
            conv2d26,
            maxpool2d1,
            maxpool2d2,
            maxpool2d3,
            conv2d27,
            resize1,
            conv2d28,
            conv2d29,
            conv2d30,
            conv2d31,
            resize2,
            conv2d32,
            conv2d33,
            conv2d34,
            conv2d35,
            conv2d36,
            conv2d37,
            conv2d38,
            device: device.clone(),
        }
    }
    #[allow(clippy::let_and_return, clippy::approx_constant)]
    pub fn forward(
        &self,
        concat3_out1: Tensor<4>,
        mul13_out1: Tensor<4>,
    ) -> (Tensor<4>, Tensor<4>, Tensor<4>, Tensor<4>) {
        let conv2d20_out1 = self.conv2d20.forward(concat3_out1);
        let sigmoid20_out1 = burn::tensor::activation::sigmoid(conv2d20_out1.clone());
        let mul20_out1 = conv2d20_out1.mul(sigmoid20_out1);
        let conv2d21_out1 = self.conv2d21.forward(mul20_out1.clone());
        let sigmoid21_out1 = burn::tensor::activation::sigmoid(conv2d21_out1.clone());
        let mul21_out1 = conv2d21_out1.mul(sigmoid21_out1);
        let conv2d22_out1 = self.conv2d22.forward(mul21_out1);
        let sigmoid22_out1 = burn::tensor::activation::sigmoid(conv2d22_out1.clone());
        let mul22_out1 = conv2d22_out1.mul(sigmoid22_out1);
        let split_tensors = mul22_out1.split_with_sizes([128, 128].into(), 1);
        let [split4_out1, split4_out2] = split_tensors.try_into().unwrap();
        let conv2d23_out1 = self.conv2d23.forward(split4_out2.clone());
        let sigmoid23_out1 = burn::tensor::activation::sigmoid(conv2d23_out1.clone());
        let mul23_out1 = conv2d23_out1.mul(sigmoid23_out1);
        let conv2d24_out1 = self.conv2d24.forward(mul23_out1);
        let sigmoid24_out1 = burn::tensor::activation::sigmoid(conv2d24_out1.clone());
        let mul24_out1 = conv2d24_out1.mul(sigmoid24_out1);
        let add6_out1 = split4_out2.clone().add(mul24_out1);
        let concat4_out1 =
            burn::tensor::Tensor::cat([split4_out1, split4_out2, add6_out1].into(), 1);
        let conv2d25_out1 = self.conv2d25.forward(concat4_out1);
        let sigmoid25_out1 = burn::tensor::activation::sigmoid(conv2d25_out1.clone());
        let mul25_out1 = conv2d25_out1.mul(sigmoid25_out1);
        let conv2d26_out1 = self.conv2d26.forward(mul25_out1);
        let maxpool2d1_out1 = self.maxpool2d1.forward(conv2d26_out1.clone());
        let maxpool2d2_out1 = self.maxpool2d2.forward(maxpool2d1_out1.clone());
        let maxpool2d3_out1 = self.maxpool2d3.forward(maxpool2d2_out1.clone());
        let concat5_out1 = burn::tensor::Tensor::cat(
            [
                conv2d26_out1,
                maxpool2d1_out1,
                maxpool2d2_out1,
                maxpool2d3_out1,
            ]
            .into(),
            1,
        );
        let conv2d27_out1 = self.conv2d27.forward(concat5_out1);
        let sigmoid26_out1 = burn::tensor::activation::sigmoid(conv2d27_out1.clone());
        let mul26_out1 = conv2d27_out1.mul(sigmoid26_out1);
        let resize1_out1 = self.resize1.forward(mul26_out1.clone());
        let concat6_out1 = burn::tensor::Tensor::cat([resize1_out1, mul20_out1].into(), 1);
        let conv2d28_out1 = self.conv2d28.forward(concat6_out1);
        let sigmoid27_out1 = burn::tensor::activation::sigmoid(conv2d28_out1.clone());
        let mul27_out1 = conv2d28_out1.mul(sigmoid27_out1);
        let split_tensors = mul27_out1.split_with_sizes([64, 64].into(), 1);
        let [split5_out1, split5_out2] = split_tensors.try_into().unwrap();
        let conv2d29_out1 = self.conv2d29.forward(split5_out2.clone());
        let sigmoid28_out1 = burn::tensor::activation::sigmoid(conv2d29_out1.clone());
        let mul28_out1 = conv2d29_out1.mul(sigmoid28_out1);
        let conv2d30_out1 = self.conv2d30.forward(mul28_out1);
        let sigmoid29_out1 = burn::tensor::activation::sigmoid(conv2d30_out1.clone());
        let mul29_out1 = conv2d30_out1.mul(sigmoid29_out1);
        let concat7_out1 =
            burn::tensor::Tensor::cat([split5_out1, split5_out2, mul29_out1].into(), 1);
        let conv2d31_out1 = self.conv2d31.forward(concat7_out1);
        let sigmoid30_out1 = burn::tensor::activation::sigmoid(conv2d31_out1.clone());
        let mul30_out1 = conv2d31_out1.mul(sigmoid30_out1);
        let resize2_out1 = self.resize2.forward(mul30_out1.clone());
        let concat8_out1 = burn::tensor::Tensor::cat([resize2_out1, mul13_out1].into(), 1);
        let conv2d32_out1 = self.conv2d32.forward(concat8_out1);
        let sigmoid31_out1 = burn::tensor::activation::sigmoid(conv2d32_out1.clone());
        let mul31_out1 = conv2d32_out1.mul(sigmoid31_out1);
        let split_tensors = mul31_out1.split_with_sizes([32, 32].into(), 1);
        let [split6_out1, split6_out2] = split_tensors.try_into().unwrap();
        let conv2d33_out1 = self.conv2d33.forward(split6_out2.clone());
        let sigmoid32_out1 = burn::tensor::activation::sigmoid(conv2d33_out1.clone());
        let mul32_out1 = conv2d33_out1.mul(sigmoid32_out1);
        let conv2d34_out1 = self.conv2d34.forward(mul32_out1);
        let sigmoid33_out1 = burn::tensor::activation::sigmoid(conv2d34_out1.clone());
        let mul33_out1 = conv2d34_out1.mul(sigmoid33_out1);
        let concat9_out1 =
            burn::tensor::Tensor::cat([split6_out1, split6_out2, mul33_out1].into(), 1);
        let conv2d35_out1 = self.conv2d35.forward(concat9_out1);
        let sigmoid34_out1 = burn::tensor::activation::sigmoid(conv2d35_out1.clone());
        let mul34_out1 = conv2d35_out1.mul(sigmoid34_out1);
        let conv2d36_out1 = self.conv2d36.forward(mul34_out1.clone());
        let conv2d37_out1 = self.conv2d37.forward(mul34_out1.clone());
        let conv2d38_out1 = self.conv2d38.forward(mul34_out1);
        let sigmoid35_out1 = burn::tensor::activation::sigmoid(conv2d36_out1.clone());
        let sigmoid36_out1 = burn::tensor::activation::sigmoid(conv2d37_out1.clone());
        let sigmoid37_out1 = burn::tensor::activation::sigmoid(conv2d38_out1.clone());
        let mul35_out1 = conv2d36_out1.mul(sigmoid35_out1);
        let mul36_out1 = conv2d37_out1.mul(sigmoid36_out1);
        let mul37_out1 = conv2d38_out1.mul(sigmoid37_out1);
        let concat10_out1 = burn::tensor::Tensor::cat([mul35_out1, mul30_out1].into(), 1);
        (mul36_out1, mul37_out1, concat10_out1, mul26_out1)
    }
}
#[derive(Module, Debug)]
pub struct Submodule3 {
    conv2d39: Conv2d,
    conv2d40: Conv2d,
    conv2d41: Conv2d,
    conv2d42: Conv2d,
    conv2d43: Conv2d,
    conv2d44: Conv2d,
    conv2d45: Conv2d,
    conv2d46: Conv2d,
    conv2d47: Conv2d,
    conv2d48: Conv2d,
    conv2d49: Conv2d,
    conv2d50: Conv2d,
    conv2d51: Conv2d,
    conv2d52: Conv2d,
    conv2d53: Conv2d,
    conv2d54: Conv2d,
    conv2d55: Conv2d,
    conv2d56: Conv2d,
    conv2d57: Conv2d,
    conv2d58: Conv2d,
    conv2d59: Conv2d,
    conv2d60: Conv2d,
    conv2d61: Conv2d,
    conv2d62: Conv2d,
    conv2d63: Conv2d,
    conv2d64: Conv2d,
    constant138: burn::module::Param<Tensor<3>>,
    constant139: burn::module::Param<Tensor<3>>,
    constant140: burn::module::Param<Tensor<1>>,
    constant141: burn::module::Param<Tensor<2>>,
    #[module(skip)]
    device: Device,
}
impl Submodule3 {
    #[allow(unused_variables)]
    pub fn new(device: &Device) -> Self {
        let conv2d39 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d40 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d41 = Conv2dConfig::new([192, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d42 = Conv2dConfig::new([64, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d43 = Conv2dConfig::new([64, 1], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d44 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d45 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d46 = Conv2dConfig::new([192, 128], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d47 = Conv2dConfig::new([128, 128], [3, 3])
            .with_stride([2, 2])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d48 = Conv2dConfig::new([128, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d49 = Conv2dConfig::new([128, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d50 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d51 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d52 = Conv2dConfig::new([384, 256], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d53 = Conv2dConfig::new([64, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d54 = Conv2dConfig::new([64, 1], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d55 = Conv2dConfig::new([128, 128], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d56 = Conv2dConfig::new([128, 128], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d57 = Conv2dConfig::new([384, 256], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d58 = Conv2dConfig::new([256, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d59 = Conv2dConfig::new([256, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d60 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d61 = Conv2dConfig::new([64, 64], [3, 3])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Explicit(1, 1, 1, 1))
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d62 = Conv2dConfig::new([64, 64], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d63 = Conv2dConfig::new([64, 1], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(true)
            .init(device);
        let conv2d64 = Conv2dConfig::new([16, 1], [1, 1])
            .with_stride([1, 1])
            .with_padding(PaddingConfig2d::Valid)
            .with_dilation([1, 1])
            .with_groups(1)
            .with_bias(false)
            .init(device);
        let constant138: burn::module::Param<Tensor<3>> = burn::module::Param::uninitialized(
            burn::module::ParamId::new(),
            move |device, _require_grad| {
                Tensor::<3>::zeros([1, 2, 8400], (device, burn::tensor::DType::F32))
            },
            device.clone(),
            false,
            [1, 2, 8400].into(),
        );
        let constant139: burn::module::Param<Tensor<3>> = burn::module::Param::uninitialized(
            burn::module::ParamId::new(),
            move |device, _require_grad| {
                Tensor::<3>::zeros([1, 2, 8400], (device, burn::tensor::DType::F32))
            },
            device.clone(),
            false,
            [1, 2, 8400].into(),
        );
        let constant140: burn::module::Param<Tensor<1>> = burn::module::Param::uninitialized(
            burn::module::ParamId::new(),
            move |device, _require_grad| {
                Tensor::<1>::from_data(
                    burn::tensor::TensorData::from([2f64]),
                    (device, burn::tensor::DType::F32),
                )
            },
            device.clone(),
            false,
            [1].into(),
        );
        let constant141: burn::module::Param<Tensor<2>> = burn::module::Param::uninitialized(
            burn::module::ParamId::new(),
            move |device, _require_grad| {
                Tensor::<2>::zeros([1, 8400], (device, burn::tensor::DType::F32))
            },
            device.clone(),
            false,
            [1, 8400].into(),
        );
        Self {
            conv2d39,
            conv2d40,
            conv2d41,
            conv2d42,
            conv2d43,
            conv2d44,
            conv2d45,
            conv2d46,
            conv2d47,
            conv2d48,
            conv2d49,
            conv2d50,
            conv2d51,
            conv2d52,
            conv2d53,
            conv2d54,
            conv2d55,
            conv2d56,
            conv2d57,
            conv2d58,
            conv2d59,
            conv2d60,
            conv2d61,
            conv2d62,
            conv2d63,
            conv2d64,
            constant138,
            constant139,
            constant140,
            constant141,
            device: device.clone(),
        }
    }
    #[allow(clippy::let_and_return, clippy::approx_constant)]
    pub fn forward(
        &self,
        mul36_out1: Tensor<4>,
        mul37_out1: Tensor<4>,
        concat10_out1: Tensor<4>,
        mul26_out1: Tensor<4>,
    ) -> Tensor<3> {
        let conv2d39_out1 = self.conv2d39.forward(mul36_out1);
        let conv2d40_out1 = self.conv2d40.forward(mul37_out1);
        let conv2d41_out1 = self.conv2d41.forward(concat10_out1);
        let sigmoid38_out1 = burn::tensor::activation::sigmoid(conv2d39_out1.clone());
        let sigmoid39_out1 = burn::tensor::activation::sigmoid(conv2d40_out1.clone());
        let sigmoid40_out1 = burn::tensor::activation::sigmoid(conv2d41_out1.clone());
        let mul38_out1 = conv2d39_out1.mul(sigmoid38_out1);
        let mul39_out1 = conv2d40_out1.mul(sigmoid39_out1);
        let mul40_out1 = conv2d41_out1.mul(sigmoid40_out1);
        let conv2d42_out1 = self.conv2d42.forward(mul38_out1);
        let conv2d43_out1 = self.conv2d43.forward(mul39_out1);
        let split_tensors = mul40_out1.split_with_sizes([64, 64].into(), 1);
        let [split7_out1, split7_out2] = split_tensors.try_into().unwrap();
        let reshape1_out1 = conv2d42_out1.reshape([1, 64, -1]);
        let reshape2_out1 = conv2d43_out1.reshape([1, 1, -1]);
        let conv2d44_out1 = self.conv2d44.forward(split7_out2.clone());
        let sigmoid41_out1 = burn::tensor::activation::sigmoid(conv2d44_out1.clone());
        let mul41_out1 = conv2d44_out1.mul(sigmoid41_out1);
        let conv2d45_out1 = self.conv2d45.forward(mul41_out1);
        let sigmoid42_out1 = burn::tensor::activation::sigmoid(conv2d45_out1.clone());
        let mul42_out1 = conv2d45_out1.mul(sigmoid42_out1);
        let concat11_out1 =
            burn::tensor::Tensor::cat([split7_out1, split7_out2, mul42_out1].into(), 1);
        let conv2d46_out1 = self.conv2d46.forward(concat11_out1);
        let sigmoid43_out1 = burn::tensor::activation::sigmoid(conv2d46_out1.clone());
        let mul43_out1 = conv2d46_out1.mul(sigmoid43_out1);
        let conv2d47_out1 = self.conv2d47.forward(mul43_out1.clone());
        let conv2d48_out1 = self.conv2d48.forward(mul43_out1.clone());
        let conv2d49_out1 = self.conv2d49.forward(mul43_out1);
        let sigmoid44_out1 = burn::tensor::activation::sigmoid(conv2d47_out1.clone());
        let sigmoid45_out1 = burn::tensor::activation::sigmoid(conv2d48_out1.clone());
        let sigmoid46_out1 = burn::tensor::activation::sigmoid(conv2d49_out1.clone());
        let mul44_out1 = conv2d47_out1.mul(sigmoid44_out1);
        let mul45_out1 = conv2d48_out1.mul(sigmoid45_out1);
        let mul46_out1 = conv2d49_out1.mul(sigmoid46_out1);
        let concat12_out1 = burn::tensor::Tensor::cat([mul44_out1, mul26_out1].into(), 1);
        let conv2d50_out1 = self.conv2d50.forward(mul45_out1);
        let conv2d51_out1 = self.conv2d51.forward(mul46_out1);
        let conv2d52_out1 = self.conv2d52.forward(concat12_out1);
        let sigmoid47_out1 = burn::tensor::activation::sigmoid(conv2d50_out1.clone());
        let sigmoid48_out1 = burn::tensor::activation::sigmoid(conv2d51_out1.clone());
        let sigmoid49_out1 = burn::tensor::activation::sigmoid(conv2d52_out1.clone());
        let mul47_out1 = conv2d50_out1.mul(sigmoid47_out1);
        let mul48_out1 = conv2d51_out1.mul(sigmoid48_out1);
        let mul49_out1 = conv2d52_out1.mul(sigmoid49_out1);
        let conv2d53_out1 = self.conv2d53.forward(mul47_out1);
        let conv2d54_out1 = self.conv2d54.forward(mul48_out1);
        let split_tensors = mul49_out1.split_with_sizes([128, 128].into(), 1);
        let [split8_out1, split8_out2] = split_tensors.try_into().unwrap();
        let reshape3_out1 = conv2d53_out1.reshape([1, 64, -1]);
        let reshape4_out1 = conv2d54_out1.reshape([1, 1, -1]);
        let conv2d55_out1 = self.conv2d55.forward(split8_out2.clone());
        let sigmoid50_out1 = burn::tensor::activation::sigmoid(conv2d55_out1.clone());
        let mul50_out1 = conv2d55_out1.mul(sigmoid50_out1);
        let conv2d56_out1 = self.conv2d56.forward(mul50_out1);
        let sigmoid51_out1 = burn::tensor::activation::sigmoid(conv2d56_out1.clone());
        let mul51_out1 = conv2d56_out1.mul(sigmoid51_out1);
        let concat13_out1 =
            burn::tensor::Tensor::cat([split8_out1, split8_out2, mul51_out1].into(), 1);
        let conv2d57_out1 = self.conv2d57.forward(concat13_out1);
        let sigmoid52_out1 = burn::tensor::activation::sigmoid(conv2d57_out1.clone());
        let mul52_out1 = conv2d57_out1.mul(sigmoid52_out1);
        let conv2d58_out1 = self.conv2d58.forward(mul52_out1.clone());
        let conv2d59_out1 = self.conv2d59.forward(mul52_out1);
        let sigmoid53_out1 = burn::tensor::activation::sigmoid(conv2d58_out1.clone());
        let sigmoid54_out1 = burn::tensor::activation::sigmoid(conv2d59_out1.clone());
        let mul53_out1 = conv2d58_out1.mul(sigmoid53_out1);
        let mul54_out1 = conv2d59_out1.mul(sigmoid54_out1);
        let conv2d60_out1 = self.conv2d60.forward(mul53_out1);
        let conv2d61_out1 = self.conv2d61.forward(mul54_out1);
        let sigmoid55_out1 = burn::tensor::activation::sigmoid(conv2d60_out1.clone());
        let sigmoid56_out1 = burn::tensor::activation::sigmoid(conv2d61_out1.clone());
        let mul55_out1 = conv2d60_out1.mul(sigmoid55_out1);
        let mul56_out1 = conv2d61_out1.mul(sigmoid56_out1);
        let conv2d62_out1 = self.conv2d62.forward(mul55_out1);
        let conv2d63_out1 = self.conv2d63.forward(mul56_out1);
        let reshape5_out1 = conv2d62_out1.reshape([1, 64, -1]);
        let reshape6_out1 = conv2d63_out1.reshape([1, 1, -1]);
        let concat14_out1 =
            burn::tensor::Tensor::cat([reshape1_out1, reshape3_out1, reshape5_out1].into(), 2);
        let concat15_out1 =
            burn::tensor::Tensor::cat([reshape2_out1, reshape4_out1, reshape6_out1].into(), 2);
        let reshape7_out1 = concat14_out1.reshape([1, 4, 16, 8400]);
        let sigmoid57_out1 = burn::tensor::activation::sigmoid(concat15_out1);
        let transpose1_out1 = reshape7_out1.permute([0, 3, 1, 2]);
        let softmax1_out1 = burn::tensor::activation::softmax(transpose1_out1, 3);
        let transpose2_out1 = softmax1_out1.permute([0, 3, 2, 1]);
        let conv2d64_out1 = self.conv2d64.forward(transpose2_out1);
        let reshape8_out1 = conv2d64_out1.reshape([1, 4, 8400]);
        let slice1_out1 = reshape8_out1.clone().slice(s![.., 0..2, ..]);
        let slice2_out1 = reshape8_out1.slice(s![.., 2..4, ..]);
        let constant138_out1 = self.constant138.val();
        let sub1_out1 = constant138_out1.sub(slice1_out1);
        let constant139_out1 = self.constant139.val();
        let add7_out1 = constant139_out1.add(slice2_out1);
        let add8_out1 = sub1_out1.clone().add(add7_out1.clone());
        let sub2_out1 = add7_out1.sub(sub1_out1);
        let constant140_out1 = self.constant140.val();
        let div1_out1 = add8_out1.div((constant140_out1).unsqueeze_dims(&[0isize, 1isize]));
        let concat16_out1 = burn::tensor::Tensor::cat([div1_out1, sub2_out1].into(), 1);
        let constant141_out1 = self.constant141.val();
        let mul57_out1 = concat16_out1.mul((constant141_out1).unsqueeze_dims(&[0isize]));
        let concat17_out1 = burn::tensor::Tensor::cat([mul57_out1, sigmoid57_out1].into(), 1);
        concat17_out1
    }
}

#[derive(Module, Debug)]
pub struct Model {
    submodule1: Submodule1,
    submodule2: Submodule2,
    submodule3: Submodule3,
    #[module(skip)]
    device: Device,
}

extern crate std;

#[cfg(not(target_arch = "wasm32"))]
impl Default for Model {
    fn default() -> Self {
        Self::from_file("weights/detection/best.bpk", &Default::default())
    }
}

impl Model {
    /// Load model weights from a burnpack file.
    #[cfg(not(target_arch = "wasm32"))]
    pub fn from_file<P: AsRef<std::path::Path>>(file: P, device: &Device) -> Self {
        let mut model = Self::new(device);
        let mut store = BurnpackStore::from_file(&file);
        model.load_from(&mut store).unwrap_or_else(|e| {
            panic!(
                "Failed to load burnpack file {}: {e}",
                file.as_ref().display()
            )
        });
        model
    }

    /// Load model weights from in-memory bytes.
    ///
    /// The bytes must be the contents of a `.bpk` file.
    pub fn from_bytes(bytes: Bytes, device: &Device) -> Self {
        let mut model = Self::new(device);
        let mut store = BurnpackStore::from_bytes(Some(bytes));
        model
            .load_from(&mut store)
            .unwrap_or_else(|e| panic!("Failed to load burnpack bytes: {e}"));
        model
    }
}

impl Model {
    #[allow(unused_variables)]
    pub fn new(device: &Device) -> Self {
        let submodule1 = Submodule1::new(device);
        let submodule2 = Submodule2::new(device);
        let submodule3 = Submodule3::new(device);
        Self {
            submodule1,
            submodule2,
            submodule3,
            device: device.clone(),
        }
    }

    #[allow(clippy::let_and_return, clippy::approx_constant)]
    pub fn forward(&self, images: Tensor<4>) -> Tensor<3> {
        let (concat3_out1, mul13_out1) = self.submodule1.forward(images);
        let (mul36_out1, mul37_out1, concat10_out1, mul26_out1) =
            self.submodule2.forward(concat3_out1, mul13_out1);
        let concat17_out1 =
            self.submodule3
                .forward(mul36_out1, mul37_out1, concat10_out1, mul26_out1);
        concat17_out1
    }
}
