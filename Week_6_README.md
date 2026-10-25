# Week 6: Pediatric Pneumonia Detection in Chest Radiography with ResNet-18

**Project 2: Deep Learning Applications | Individual Lab**  
**Course:** Introduction to Applied AI | BS 8th Semester | Department of Electronics  
**Dataset:** [Chest X-Ray Images (Pneumonia)](https://www.kaggle.com/datasets/paultimothymooney/chest-xray-pneumonia) by Paul Mooney / Kermany et al.  
**Backbone:** ResNet-18 (ImageNet Pre-trained)  
**Task:** Binary Classification — Normal vs. Pneumonia

---

## Executive Summary & Model Card Overview

* **Who Benefits:** Pediatricians, radiologists, and emergency room clinicians in resource-constrained hospitals and high-volume clinical triage settings.
* **Why It Matters:** Pediatric pneumonia remains the single largest infectious cause of mortality among children under five years old worldwide, accounting for over 700,000 child deaths annually. Rapid and reliable radiograph triage helps prioritize high-risk cases for immediate antimicrobial intervention while mitigating unnecessary broad-spectrum antibiotic usage.
* **Dataset:** 5,840 pediatric chest radiographs (CC BY 4.0 license) from Guangzhou Women and Children’s Medical Center; labeled by expert physicians and verified by radiologists.
* **Data Audit:** Imbalance ratio **2.9:1**; **62** exact duplicate files (all within-split; 0 across train/test); **0** near-duplicates between train and test splits; partitioned by patient identifier using `StratifiedGroupKFold(n_splits=6)` ensuring **0 shared patient groups**.
* **Imbalance Handling:** Inverse-frequency weighted Cross-Entropy Loss with exact weights:
  $$\text{Normal} = 1.935, \quad \text{Pneumonia} = 0.674$$
* **Results (Test Set, Evaluated Strictly Once):**
  * Macro-F1: **0.917** | Overall Accuracy: **92.5%** | Test ROC-AUC: **0.979**
  * Weakest Class: **Normal** (Recall: 82.5%, Precision: 97.0%, F1: 0.891)
  * Target Recall Operating Point ($t = 0.366$, chosen on validation for recall $\ge 0.95$):
    * Test Sensitivity (Recall): **99.0%** (386 / 390 cases detected)
    * Test Specificity: **80.3%** (188 / 234 healthy controls identified)
    * Test-set PPV (Prevalence 62.5%): **89.4%**
    * Outpatient Screening PPV (Prevalence 5.0%): **20.9%** (Bayes' Theorem / Base-Rate Falloff)
* **Grad-CAM Saliency & Shortcut Audit:** Saliency heatmaps confirmed that true normal classifications rely on bilateral pulmonary aeration. However, erroneous false-positive classifications were triggered by **non-pulmonary peripheral shortcuts**: radiopaque orientation letters (**'R' marker text**), shoulder soft tissues, and humerus bone edges. Shortcut suspected and confirmed for peripheral false alarms.
* **Limitations:** Exclusively pediatric cohort (ages 1–5) from a single medical center in China; not validated on adult or geriatric patients, portable bedside X-rays, multi-pathology cases (e.g., COVID-19, TB, lung cancer), or images with varied acquisition parameters. **Strictly not for autonomous clinical decision-making.**

---

## 1. Dataset Audit & Pre-Processing Analysis (Part 1)

### 1.1 Class Distribution & Imbalance Ratio
* **Normal Cases:** 1,341 images ($25.7\%$)
* **Pneumonia Cases:** 3,875 images ($74.3\%$)
* **Total Training Set:** 5,216 images
* **Class Imbalance Ratio (Max / Min):**
  $$\text{Imbalance Ratio} = \frac{3,875}{1,341} \approx \mathbf{2.89:1 \quad (\sim 2.9:1)}$$
* **Images Per Subject Group:** **1.83 images per group** on average, demonstrating that patients frequently contribute multiple radiograph exposures.

### 1.2 Image Geometry and Color Formats
* **Spatial Resolution:**
  * Width ($w$): Min = 384 px, Median ($50\%$) = 1,300 px, Max = 2,510 px
  * Height ($h$): Min = 127 px, Median ($50\%$) = 890 px, Max = 2,543 px
* **Color Channels:** 95.3% grayscale (`'L'`: 286 / 300 sampled), 4.7% stored as 3-channel RGB (`'RGB'`: 14 / 300 sampled). All images represent transmission radiography and were standardized to 3-channel grayscale inputs for ResNet transfer learning.

### 1.3 First Shortcut Suspect Identified
During visual inspection of the 5×2 sample grid, noticeable non-pulmonary visual features were observed:
1. **High-contrast Radiopaque Text Markers:** Prominent letters like **'R'** (patient right indicator) and equipment stamps (e.g., `'KV59'`) in corner margins.
2. **Pediatric Restraint & Posture:** Raised pediatric arms in immobilization frames, prominent clavicles, and differing diaphragm heights.
3. **Collimator Edge Padding:** Variable black peripheral border padding.
* **Primary Suspect:** The presence, typeface, and intensity of radiopaque orientation letters ('R'). The network could correlate white ink in margin pixels with pathology rather than inspecting pulmonary parenchymal opacity.

---

## 2. Leakage Audit & Group-Aware Splitting (Part 2)

### 2.1 Exact & Near-Duplicate Analysis
* **Exact Duplicates (MD5 Byte Hash):**
  * **62 duplicate files** were detected across 30 unique content hashes.
  * Intra-split duplicate breakdown:
    * `(train, train)`: 22 pairs
    * `(test, test)`: 6 pairs
    * `(train, train, train)`: 2 triplets
  * **Cross-Split Duplicates (`train ↔ test`): 0.** No byte-identical files leaked between train and test.
  * **Label Consistency:** 100% consistent (all duplicate clusters have label cardinality = 1).
* **Near-Duplicates (Standardized 32×32 Perceptual Thumbnails):**
  * Evaluated across all images using mean absolute pixel differences ($L_1$ distance in standard deviation units).
  * **0 out of 624 test images** possessed a near-duplicate in the training split (closest distance was $0.164$, exceeding the $0.10$ leakage threshold).

### 2.2 Subject Grouping and Partitioning
* **Group Regex Pattern:** `(person\d+|IM-\d+|NORMAL2-IM-\d+)`
* **Splitting Strategy:** `StratifiedGroupKFold(n_splits=6, shuffle=True, random_state=42)`
  * **Train Split:** 4,354 images
  * **Validation Split:** 862 images (646 Pneumonia, 216 Normal)
  * **Test Split:** 624 images (fixed standard benchmark)
  * **Shared Groups (Train $\cap$ Val):** **0** (strictly 0 patient leakage).

### 2.3 Counterfactual: Random vs. Group-Aware Split
If an un-grouped random split had been executed, sequential radiographs from the exact same pediatric patient would have been distributed across both the training and test partitions. The deep neural network would have memorized patient-specific anatomical characteristics (rib cage dimensions, cardiac silhouette contour, clavicle positioning) and hospital scanner artifacts instead of learning generalizable pathology. This would produce **falsely inflated test accuracy that fails completely when deployed on unseen patients in a clinic**.

---

## 3. Data Transforms & Imbalance Remediation (Part 3)

### 3.1 Class Weights Derivation & Arithmetic
To counteract the 2.9:1 class imbalance without discarding data, inverse-frequency class weighting was computed:
$$\text{Formula:} \quad w_c = \frac{N}{K \times n_c}$$
Where $N = 4,354$ (training set), $K = 2$ classes, $n_{\text{NORMAL}} = 1,125$, and $n_{\text{PNEUMONIA}} = 3,229$:

* $$w(\text{NORMAL}) = \frac{4,354}{2 \times 1,125} = \frac{4,354}{2,250} \approx \mathbf{1.935}$$
* $$w(\text{PNEUMONIA}) = \frac{4,354}{2 \times 3,229} = \frac{4,354}{6,458} \approx \mathbf{0.674}$$

The loss weight penalty on Normal misclassifications is $\frac{1.935}{0.674} \approx 2.87\times$ higher than Pneumonia, preventing the optimizer from ignoring healthy controls.

### 3.2 Domain-Specific Augmentation Rationale
* **Included Augmentations:**
  * `RandomResizedCrop(224, scale=(0.8, 1.0))`: Simulates detector distance variability and collimator field adjustments without clipping whole lung fields.
  * `RandomRotation(10)`: Captures slight patient tilting ($\pm 10^\circ$) common in pediatric radiography.
  * `ColorJitter(brightness=0.15, contrast=0.15)`: Simulates real-world variability in tube voltage ($kVp$) and digital imaging plate transfer curves.
* **Deliberately Excluded Augmentations:**
  * **`RandomHorizontalFlip` (STRICTLY FORBIDDEN):** Human chest anatomy is naturally asymmetric (levocardia, aortic arch on the left, liver and three pulmonary lobes on the right). Flipping images horizontally generates unphysiological anatomy (*situs inversus*) and disrupts spatial feature localization.
  * **`RandomVerticalFlip` (STRICTLY FORBIDDEN):** Radiographs are never acquired inverted.

---

## 4. Model Architecture & Two-Phase Training (Part 4)

### 4.1 Architecture
* **Backbone:** ResNet-18 (ImageNet pre-trained weights `ResNet18_Weights.DEFAULT`)
* **Classification Head:** Linear layer ($512 \to 2$) with Cross-Entropy Loss
* **Trainable Parameters in Phase 1:** 1,026 parameters

### 4.2 Training Progression & Macro-F1 Model Selection
Model checkpoints were evaluated and selected strictly by **Validation Macro-F1**, never simple accuracy:

| Phase | Epoch | Val Macro-F1 | Epoch Time | Key Observation |
|---|---|---|---|---|
| **Phase 1: Head Only** | Epoch 1 | 0.847 | 67s | Rapid initial adaptation |
| | Epoch 2 | **0.881** | 69s | Best Phase 1 checkpoint |
| **Phase 2: Fine-Tuning** | Epoch 1 | **0.945** | 69s | **Peak Validation Performance** |
| (`layer4` + Head) | Epoch 2 | 0.941 | 69s | Slight plateau |
| | Epoch 3 | 0.916 | 68s | Early signs of validation overfit |

* **Did Fine-Tuning Help?** Yes. Unfreezing `layer4` with differential learning rates ($10^{-4}$ for convolutional layers, $10^{-3}$ for classification head) produced an absolute validation macro-F1 gain of **+0.064 (+6.4 percentage points)**, enabling deeper filters to capture diffuse radiographic infiltrates and consolidation patterns.

---

## 5. Test Evaluation & Decision Thresholding (Part 5)

### 5.1 Test-Set Performance (Evaluated Once)
Evaluated on the untouched 624-image test set:

| Class | Precision | Recall | F1-Score | Support |
|---|---|---|---|---|
| **NORMAL** | 0.970 | 0.825 | 0.891 | 234 |
| **PNEUMONIA** | 0.904 | 0.985 | 0.942 | 390 |
| **Accuracy** | | | **0.925** | 624 |
| **Macro Average** | **0.937** | **0.905** | **0.917** | 624 |
| **Weighted Average** | 0.928 | 0.925 | 0.923 | 624 |

* **Confusion Matrix:**
  * True Normal, Pred Normal: **193**
  * True Normal, Pred Pneumonia (False Positive): **41**
  * True Pneumonia, Pred Normal (False Negative): **6**
  * True Pneumonia, Pred Pneumonia: **384**
* **Weakest Class:** Normal (Recall: 82.5% vs. 98.5%). The model prioritizes sensitivity over specificity.

### 5.2 Validation-Tuned Operating Threshold ($t = 0.366$)
To meet the clinical requirement of $\text{Recall} \ge 95\%$ on pneumonia, the classification threshold was tuned strictly on the validation set:
* **Operating Threshold:** **$t = 0.366$** (lowered from default 0.50)
* **Test Sensitivity (Pneumonia Recall):** **0.990 (99.0%)** $\to$ Exceeded 95% target!
* **Test Specificity:** **0.803 (80.3%)**
* **Test ROC-AUC:** **0.979**

### 5.3 PPV and the Screening Paradox (Bayes' Theorem by Hand)
Positive Predictive Value represents the probability that a positive test indicates true disease:
$$\text{PPV} = \frac{\text{Sens} \times \text{Prev}}{(\text{Sens} \times \text{Prev}) + ((1 - \text{Spec}) \times (1 - \text{Prev}))}$$

1. **At Test-Set Prevalence ($62.5\%$):**
   $$\text{PPV}_{\text{test}} = \frac{0.990 \times 0.625}{(0.990 \times 0.625) + (0.197 \times 0.375)} = \frac{0.6186}{0.6186 + 0.0737} = \mathbf{0.894 \quad (89.4\%)}$$
2. **At Realistic Outpatient Screening Prevalence ($5.0\%$):**
   $$\text{PPV}_{\text{screening}} = \frac{0.990 \times 0.05}{(0.990 \times 0.05) + (0.197 \times 0.95)} = \frac{0.0495}{0.0495 + 0.1868} = \mathbf{0.209 \quad (20.9\%)}$$

**Plain-Language Clinical Interpretation:**  
In a real-world primary care clinic where 95% of incoming patients are healthy, the test's 19.7% false-positive rate ($1 - \text{Specificity}$) acts on that large healthy cohort, producing $\approx 187$ false alarms per 1,000 screened patients alongside 50 true positives. Consequently, **almost 4 out of 5 positive screening flags ($79.1\%$) are false alarms**.

---

## 6. Saliency Analysis with Grad-CAM & Shortcut Verification (Part 6)

Grad-CAM was applied to the final residual block (`layer4`) across 3 correct and 3 incorrect test cases:

```
+-----------------------------------------------------------------------------------------+
| Top Row: Correct Predictions (True NORMAL | Pred NORMAL)                                |
| 1. Bilateral lower/mid lung fields (Legitimate)                                         |
| 2. Right lower basilar lung zone (Legitimate)                                           |
| 3. Right mid-pulmonary parenchymal zone (Legitimate)                                    |
+-----------------------------------------------------------------------------------------+
| Bottom Row: False Positives (True NORMAL | Pred PNEUMONIA)                             |
| 4. Upper lung border & high-contrast 'R' text marker (Shortcut Suspect)                 |
| 5. Outer left shoulder soft tissue & chest boundary (Shortcut Suspect)                  |
| 6. Lateral humerus/arm bone & axillary periphery (Shortcut Suspect)                    |
+-----------------------------------------------------------------------------------------+
```

* **Overall Verdict:** **Shortcut Suspected and Confirmed in Peripheral False Positives.**  
  While true negatives correctly leverage bilateral lung aeration, false-positive misclassifications are triggered by non-pulmonary edge artifacts, arm bones, and radiopaque orientation letters.
* **Recommended Verification & Remediation:**
  Apply automated lung-field segmentation (e.g., U-Net trained on anatomical chest masks) to mask all peripheral markers, shoulder margins, and background black borders prior to classification.

---

## 7. Model Governance & Four Responsibility Questions (Slide 34)

### 1. Who could be harmed and how?
* **False Negatives:** Delayed antibiotic therapy in a child with bacterial pneumonia can cause respiratory failure, sepsis, empyema, or death.
* **False Positives:** Healthy children receive unnecessary broad-spectrum antibiotics, leading to adverse drug reactions, microbiome disruption, antimicrobial resistance, and unnecessary hospital admissions.

### 2. Where was the model NOT validated?
* **Demographics:** Only pediatric patients (ages 1–5) in Guangzhou, China. Not validated on adult, elderly, or international cohorts.
* **Hardware & Settings:** Not validated on portable bedside AP units, differing exposure voltages ($kVp$), or diverse hardware vendors.
* **Comorbidities:** Not validated on patients with COVID-19, tuberculosis, asthma, congenital heart disease, or atelectasis.

### 3. What is the human role?
* The model serves exclusively as a **triage assistant and decision-support tool**.
* Final diagnosis and treatment decisions remain exclusively with board-certified radiologists and attending pediatricians.

### 4. What evidence would change conclusions?
* External multicenter validation where macro-F1 drops below 0.80.
* Lung-field segmentation masking causing a $>10\%$ decline in sensitivity, indicating excessive shortcut reliance.
* A prospective clinical trial failing to demonstrate improved diagnostic turnaround or patient outcomes.

---

## 8. Check Your Understanding — Technical Solutions

#### Q1: Why does a random split of chest X-rays overestimate performance?
* **Solution:** Patients frequently undergo multiple radiographic exposures across an illness episode. A random split scatters images from the same patient across both train and test splits, causing severe **patient-level data leakage**. The model memorizes unique patient skeletal contours and scanner idiosyncrasies rather than learning generalizable pulmonary pathology, yielding inflated test scores that collapse on new clinical populations.

#### Q2: Two classes have 900 and 100 training images. Compute both class weights with $N / (K \times n_c)$.
* **Given:** $N = 900 + 100 = 1,000$, $K = 2$, $n_0 = 900$, $n_1 = 100$.
* $$w_0 = \frac{1,000}{2 \times 900} = \frac{1,000}{1,800} = \frac{5}{9} \approx \mathbf{0.556}$$
* $$w_1 = \frac{1,000}{2 \times 100} = \frac{1,000}{200} = \mathbf{5.000}$$
* *Check:* $900(0.5555...) + 100(5.0) = 500 + 500 = 1,000 = N \quad \checkmark$

#### Q3: With focal loss and $\gamma = 2$, by what factor is an example with $p_t = 0.8$ down-weighted?
* **Solution:** Focal loss modulating factor is $(1 - p_t)^\gamma$.
* With $\gamma = 2$ and $p_t = 0.8$:
  $$\text{Modulating Factor} = (1 - 0.8)^2 = (0.2)^2 = \mathbf{0.04}$$
* The sample is down-weighted to $0.04$ of its standard cross-entropy loss, representing a down-weighting factor of:
  $$\frac{1}{0.04} = \mathbf{25\times}$$

#### Q4: Sensitivity 0.90, specificity 0.95, prevalence 2%. Compute PPV.
* **Solution:**
  $$\text{PPV} = \frac{0.90 \times 0.02}{(0.90 \times 0.02) + (0.05 \times 0.98)} = \frac{0.018}{0.018 + 0.049} = \frac{0.018}{0.067} \approx \mathbf{0.2687 \quad (26.9\%)}$$
* Over $73\%$ of positive test results are false alarms due to the low baseline prevalence.

#### Q5: When is macro-F1 a better selection metric than weighted F1?
* **Solution:** In imbalanced datasets where the minority class is critical (e.g. rare pathology detection), weighted F1 allows a model that predicts only the dominant majority class to score deceptively high. Macro-F1 weights all classes equally ($\frac{1}{K}\sum F1_k$), harshly penalizing models that fail on the minority class.

#### Q6: Grad-CAM highlights a hospital label in the corner of X-rays. What do you do next?
* **Solution:**
  1. *Verify Shortcut:* Crop or inpaint the corner region across test images and observe if prediction confidence drops.
  2. *Anatomical Masking:* Pre-process images with an automated lung segmentation model to crop only the thoracic cavity.
  3. *Adversarial Augmentation:* Train with random corner erasing or synthetic label overlays across random classes.
  4. *Multi-Center Stratification:* Ensure training datasets include radiographs across multiple institutions and scanner vendors.

---
