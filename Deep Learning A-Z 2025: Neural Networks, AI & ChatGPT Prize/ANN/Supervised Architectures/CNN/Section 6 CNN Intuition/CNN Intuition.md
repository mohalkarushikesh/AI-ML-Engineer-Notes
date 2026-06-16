## 🧠 What Are CNNs?

Convolutional Neural Networks (CNNs) are a class of deep neural networks designed specifically for **image and visual data processing**. They can automatically learn **spatial hierarchies of features** from input images. CNNs power applications like facial recognition, medical imaging analysis, and even self-driving cars.

👨‍🔬 CNNs gained prominence thanks to pioneers like **Yann LeCun**, one of the founding fathers of deep learning.

---

## 🚀 Key Steps in a CNN Pipeline

### 1️⃣ Convolution Layer

🔍 The core operation where a **filter (or kernel)** slides across the image to detect patterns.

- Input: `7×7` binary image matrix  
- Kernel: `3×3` matrix  
- Output: `5×5` feature map  
  ![Convolution Setup](https://github.com/user-attachments/assets/8b8991b0-c256-454a-88fb-4cb83afc2a55)  
  ![Feature Map Example](https://github.com/user-attachments/assets/c87b1a02-1f53-4617-91ba-a6274a50e009)

🔧 **What it does:**
- Captures local patterns like edges, textures, corners
- Low-level layers → detect edges
- Deeper layers → recognize complex shapes like faces or digits

---

## 📐 Common Filters in CNNs (Convolutional Neural Networks)

These filters are small matrices that slide over an image to **highlight specific features**. Think of them like lenses that help the network “see” edges, textures, or depth.

---

### 🔧 1. **Sharpen Filter**

**Matrix**:
```
00000
00-100
0-15-10
00-100
00000
```

**Purpose**: Makes edges and fine details pop by increasing contrast between neighboring pixels.

**Visual Effect**:  
![Sharpen Filter Example](https://www.photoshopessentials.com/photo-editing/using-smart-sharpen-for-the-best-image-sharpening-in-photoshop/)  
This filter helps CNNs detect outlines and boundaries more clearly.

---

### 🧭 2. **Edge Enhance Filter**

**Matrix**:
```
0    0    0
-1   -1   0
0    0    0
```

**Purpose**: Slightly boosts edge visibility without drastically changing the image.

**Visual Effect**:  

- Useful for detecting subtle transitions in brightness or texture.

---

### ⚠️ 3. **Edge Detect Filter** (Important!)

**Matrix**:
```
0  1  0
1 -4  1
0  1  0
```

**Purpose**: Finds sharp changes in pixel intensity—perfect for identifying object boundaries.

**Visual Effect**:  

- This is a **core filter** in computer vision tasks like object recognition and segmentation.

---

### 🗿 4. **Emboss Filter**

**Matrix**: Custom-designed to simulate lighting and shadows.

**Purpose**: Gives a 3D effect by highlighting edges with depth—like carving the image.

- Helps CNNs understand orientation and surface texture.

---

🎓 _Recommended Read_:  
**"Introduction to CNN"** – Jianxin Wu (2017)

---

### 2️⃣ Pooling Layer aka Downsampling Layer

Simplifies feature maps by reducing dimensions.

- **Max Pooling**: retains highest value in a region
- **Mean Pooling**: uses average value
- **Sum Pooling**: uses total sum

🧭 Why Pool?  
- Removes unnecessary details  
- Increases computational efficiency  
- Preserves features even in tilted or distorted images

🎓 _Recommended Read_:  
**"Evaluation of Pooling Operations"** – Domnik Scherer et al. (2010)

---

### 3️⃣ Flattening

📄 Converts 2D matrices into 1D vectors to prepare for the dense layer.

- Example: A feature map of size `5×5` becomes a vector of `25` elements.

<img width="1106" height="488" alt="image" src="https://github.com/user-attachments/assets/84c093a7-0096-439b-81b0-47dc606c6d18" />

---

### 4️⃣ Fully Connected Layer (Dense Layer)

Each neuron is connected to every neuron in the previous layer.

- Combines all learned features for final classification
- Adds **decision-making** ability to the network

---

## 🧪 Activation Layers

### 🔥 ReLU (Rectified Linear Unit)
- **Function**: `f(x) = max(0, x)`
- Introduces non-linearity  
  ![ReLU Visualization](https://github.com/user-attachments/assets/30fade0c-a15d-4f35-ba15-d0127b0c0a26)

💡 Why break linearity?  
It allows CNNs to learn **non-trivial patterns** and complex functions rather than just fitting linear boundaries.

🎓 _Recommended Reads_:
- Jay Kuo (2016): *"Understanding CNN with Mathematical Models"*  
- Kaiming He et al. (2015): *"Delving Deep into Rectifiers"*

---

![unnamed8PDPDZ_1_1ZBHFR](https://github.com/user-attachments/assets/31572f51-a1bf-4d27-a73b-6519c0eb0826)

---

## 🎯 Extra Topics

### 🎯 **Softmax & Cross-Entropy**

#### 📊 Softmax Function  
The **Softmax** function converts raw class scores (logits) into probabilities that sum to 1.

**Formula**:
$$\text{Softmax}(z_i) = \frac{e^{z_i}}{\sum_{j=1}^{K} e^{z_j}}$$

Where:
- $z_i$ is the score for class $i$
- $K$ is the total number of classes
- $e^{z_i}$ increases confidence for higher scores

🔍 Interpretation: The higher the score $z_i$, the higher the probability assigned to class $i$.

---

#### 📉 Cross-Entropy Loss  
**Cross-Entropy** quantifies how far off the predicted probabilities are from the actual labels.

**Formula**:
$$\text{Loss} = -\sum_{i=1}^{K} y_i \cdot \log(\hat{y}_i)$$

Where:
- $y_i$ is the true label (1 for correct class, 0 for others)
- $hat{y}_i$ is the predicted probability from Softmax

🧠 In practice:  
- If your model predicts class “cat” with 90% confidence, and the correct answer is “dog,” the cross-entropy loss will be high.
- If the model is right and confident, loss is low.

🎓 _Recommended Read_:
**"A Friendly Introduction to Cross Entropy Loss"** - by Rob DiPitro (2016)

🎓 _Recommended Read_:  
**"How to Implement Neural Network Intermezzo 2"** – by Peter Roelants (2016)

---

🎓 _Recommended Read_:  
**"Gradient-based Learning Applied to Document Recognition"** – Yann LeCun (1998)

---

## 🧰 Additional CNN Concepts

| Concept           | Description |
|-------------------|-------------|
| Feature Detector  | Kernel that scans image to extract patterns |
| Filters           | Often `3×3`, `5×5`, or `7×7`—each tuned to find unique features |
| Stride            | Step size while the kernel moves over the input |
| Feature Maps      | Output from convolution layers that represent learned features |

---

**Linear flow from raw image to prediction**

```
[ Input Image (e.g., 28×28 pixels) ]
             ↓
[ Convolution Layer ]
  - Applies filters/kernels
  - Produces feature maps
             ↓
[ Activation Layer (ReLU) ]
  - Adds non-linearity
  - Only positive values retained
             ↓
[ Pooling Layer (e.g., Max Pooling) ]
  - Reduces spatial size
  - Keeps important features
             ↓
[ Convolution + ReLU + Pooling (repeated) ]
  - Deeper feature extraction
             ↓
[ Flattening ]
  - Converts 2D maps into 1D vector
             ↓
[ Fully Connected Layer ]
  - Dense connections
  - Learns complex relationships
             ↓
[ Output Layer (e.g., Softmax) ]
  - Probabilities for each class

```

<img width="1105" height="583" alt="image" src="https://github.com/user-attachments/assets/1498aa99-71f1-48ee-ac79-cabe93fc015e" />

---

🎓 _Recommended Read_:  
**"The 9 Deep Learning Papers you need to know about (Understanding the CNN part - 3)"** – Adit Deshpande (2016)


---
## Temp Notes

# CNN Notes

## Convolution Layer

* Applies filters (kernels) to the input image.
* Generates **feature maps**.
* Feature maps become the input to the next layer.
* As image size decreases through convolution and pooling layers, the number of filters is usually increased.

---

## Pooling Layer

Pooling reduces the spatial dimensions of feature maps by representing neighboring values with a single value.

### Max Pooling

* Uses a window (e.g., 2×2).
* Selects the **maximum value** within the window.
* Slides across the feature map and repeats the operation.

### Average Pooling

* Uses a window (e.g., 2×2).
* Computes the **average value** within the window.
* Reduces dimensions while preserving overall information.

> **Note:** Pooling does **not** create new feature maps. It only downsamples and compresses the existing feature maps.

---

## Flatten Layer

* Applied after the final pooling layer.
* Converts the 2D feature maps into a 1D vector.
* The flattened vector is passed to fully connected layers for classification.

---

## CNN Workflow

1. **Convolution** : Generates new feature maps.

2. **Activation (Non-linearity)** : Introduces non-linear properties (e.g., ReLU).

3. **Pooling** :  Reduces the size of feature maps.

4. **Flatten** : Converts feature maps into a one-dimensional vector.

5. **Fully Connected Layer** : Performs classification or prediction.

