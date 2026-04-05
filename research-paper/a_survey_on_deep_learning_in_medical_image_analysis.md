
# A Survey on Deep Learning in Medical Image Analysis

## Paper Information:
Author: Litjens et al.
<br>
Keyword: Survey Paper
<br>
Year: "2017"
<br>
Link: https://arxiv.org/pdf/1702.05747


## Table 1


| Paper | Application | Description | Deep Learning Approach |
| :--- | :--- | :--- | :--- |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Disorder/Exam Classification** | Categorizing an entire scan or patient study into diagnostic groups like "diseased" or "healthy." | CNNs (often pre-trained on ImageNet), Stacked Auto-Encoders (SAEs), and Deep Belief Networks (DBNs). |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Object/Lesion Classification** | Sorting a specific, pre-identified area of interest into categories, such as "benign" vs. "malignant" tumors. | Multi-stream CNNs, 3D CNNs, and architectures that incorporate multi-scale local patches. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Object/Lesion Detection** | Automatically locating abnormalities within an image, often by placing a bounding box or point around them. | Sliding-window CNNs and Fully Convolutional Networks (fCNNs) to produce likelihood maps. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Organ/Landmark Localization** | Pinpointing specific anatomical coordinates or landmarks, such as the apex of the heart or vertebrae. | CNNs for coordinate regression and Deep Q-Networks (DQN) for reinforcement learning-based navigation. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Organ/Substructure Segmentation** | Defining the exact pixel-level boundaries of healthy anatomical structures for volume measurements. | U-net, V-net, and Recurrent Neural Networks (RNNs) like LSTMs for processing sequential image slices. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Lesion Segmentation** | Mapping the precise borders of abnormalities like tumors, which is critical for treatment planning. | Multi-pathway CNNs and U-net variants that combine high-resolution local info with global context. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Image Registration** | Mathematically aligning two or more images (e.g., from different times or modalities) into one coordinate system. | Deep regression networks to predict spatial transformation parameters and CNNs to learn similarity metrics. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Image Generation/Enhancement** | Improving image quality, reducing noise, or synthesizing one modality (like CT) from another (like MRI). | 2D and 3D CNNs used for super-resolution, denoising, and cross-modality image synthesis. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Content-based Image Retrieval** | Searching large databases to find historical medical cases that are visually similar to a new patient's scan. | CNNs used as feature extractors to generate "fingerprints" of images for efficient similarity matching. |
| [A Survey on Deep Learning in Medical Image Analysis](https://arxiv.org/abs/1702.05747) | **Report Generation/Text Integration** | Generating natural language descriptions of images or using medical reports to improve image classification. | Combinations of CNNs (for visual features) and RNNs/LSTMs (for language modeling and text generation). |

## Table 2
Deep learning is applied specifically to **brain image analysis**, which is one of the most established areas in the field.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Disorder Classification** | Focused on diagnosing conditions like Alzheimer's Disease (AD), Mild Cognitive Impairment (MCI), and Schizophrenia. | Primarily uses **Stacked Auto-Encoders (SAEs)** and **Deep Belief Networks (DBNs)** for feature extraction, often followed by an SVM classifier. |
| **Tissue & Anatomy Segmentation** | Involves pixel-wise labeling of brain tissues (Gray Matter, White Matter) and structures like the Hippocampus or Striatum. | Dominated by **CNNs** (2D and 3D) and **RNNs** (like LSTMs), which achieved state-of-the-art results on challenges like MRBrainS. |
| **Lesion & Tumor Segmentation** | Precise mapping of brain tumors, MS lesions, and lacunes. This is critical for monitoring disease progression. | Uses **3D CNNs**, **Fully Convolutional Networks (FCNs)**, and multi-scale architectures to capture both local detail and global brain context. |
| **Lesion Detection** | Automatically finding the location of microbleeds or tumors within the brain volume. | Employs **3D FCNs** for initial candidate segmentation followed by **3D CNNs** for false positive reduction. |
| **Survival & Prediction** | Predicting patient outcomes, such as survival time for tumor patients or the development of neurodevelopmental issues. | Often combines **3D CNN features** with clinical characteristics (hand-crafted features) using an SVM or specialized graph-based layers. |
| **Image Construction** | Generating one type of image from another, such as creating a CT scan from an MRI or a PET scan from an MRI. | Utilizes **3D CNNs** and **Encoder-Decoder** architectures to learn the mapping between different imaging modalities. |
| **Registration & Other** | Measuring similarity between images for alignment (registration) or modeling the variability of brain morphology. | Employs **Convolutional RBMs** and **CNNs** to predict deformation fields or estimate similarity metrics between moving and fixed images. |

## Table 3
Focuses on **Retinal Image Analysis**, which is a unique field because it deals primarily with 2D color fundus photographs and 3D Optical Coherence Tomography (OCT) scans. This area is one of the most commercially advanced for medical AI.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Vessel Segmentation** | Identifying the intricate network of blood vessels in the retina to detect changes related to diabetes or hypertension. | Primarily uses **CNNs** applied to small image patches or **Fully Convolutional Networks (FCNs)** for pixel-level mapping. |
| **Optic Disc/Cup Segmentation** | Delineating the optic disc and cup to calculate the cup-to-disc ratio, a primary indicator for Glaucoma. | **CNNs** are used to regress the boundaries, often using multi-scale approaches to capture the overall shape. |
| **Lesion Detection** | Locating specific abnormalities like hemorrhages, exudates, or microaneurysms that indicate diabetic retinopathy. | Employs **CNNs** in a sliding-window fashion or **FCNs** to create probability maps of where lesions exist. |
| **Disease Classification** | Grading the severity of Diabetic Retinopathy or detecting Age-related Macular Degeneration (AMD) from a single image. | Uses deep **CNNs** (like AlexNet or VGG) often pre-trained on ImageNet and fine-tuned on retinal datasets to classify images by severity level. |
| **OCT Layer Segmentation** | Analyzing the 3D layers of the retina in OCT scans to measure thickness or find fluid pockets. | Utilizes **3D CNNs** or combinations of **CNNs and RNNs** to maintain spatial consistency across the different layers of the scan. |
| **Fovea Localization** | Finding the center of the macula (the fovea), which is essential for orienting other diagnostic measurements. | **CNNs** are used to perform coordinate regression or to classify pixels as "fovea" vs "non-fovea." |


## Table 4
**Chest X-ray Analysis**, which is one of the most common medical imaging procedures. This area has seen a massive surge in research due to the availability of large-scale public datasets and the clear clinical need for automated triage.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Nodule Detection/Classification** | Identifying and categorizing small, potentially cancerous lumps in the lungs. | One of the earliest applications, using simple **CNNs** (dating back to Lo et al., 1995) and more modern multi-scale CNNs. |
| **Pathology Detection** | Identifying various common diseases such as pneumonia, cardiomegaly (enlarged heart), or pleural effusion from a single radiograph. | Primarily uses **pre-trained CNNs** (like GoogLeNet or AlexNet) fine-tuned on large chest X-ray datasets like ChestX-ray8. |
| **Tuberculosis (TB) Detection** | Specifically screening for TB, which is a global health priority, particularly in resource-limited settings. | Uses **CNNs** combined with **Multiple Instance Learning (MIL)** to produce "heat maps" of suspicious regions. |
| **Image Retrieval** | Finding similar historic X-ray cases from a database to assist doctors in diagnosing a new patient. | **CNNs** act as feature extractors, often combined with clinical metadata like age and gender, to find visually and clinically similar matches. |
| **Anatomical Classification** | Automatically determining if a scan is a frontal view or a lateral (side) view for organizational purposes. | Employs standard **CNNs** as a high-speed pre-processing step for hospital record-keeping systems. |
| **Bone Suppression** | Digitally "removing" the ribs and collarbones from an X-ray so that the underlying lung tissue is easier to see. | Uses a **cascade of CNNs** at increasing resolutions to learn how to predict the bone-only signal and subtract it from the image. |
| **Report Generation** | Automatically creating short text descriptions or "captions" based on the findings in the X-ray. | Combines **CNNs** (for visual features) with **Recurrent Neural Networks (RNNs)** to generate sequences of diagnostic keywords or text. |

## Table 5
Ta **Lung and Chest CT Analysis**. Unlike the 2D X-rays in Table 3, CT scans provide 3D volumetric data, which requires more complex deep learning architectures to handle the massive amount of spatial information.

| Application Category                               | Key Tasks and Remarks                                                                              | Deep Learning Approaches                                                                                                                            |
| :------------------------------------------------- | :------------------------------------------------------------------------------------------------- | :-------------------------------------------------------------------------------------------------------------------------------------------------- |
| **Nodule Detection**                               | Locating tiny lung nodules within the 3D lung volume. This is the most researched area in lung CT. | Uses **3D CNNs** or "multi-view" **2.5D CNNs** (which look at 3 orthogonal 2D slices simultaneously) to find candidates and reduce false positives. |
| **Nodule Classification**                          | Determining if a detected lung nodule is benign or malignant.                                      | Employs **Multi-scale CNNs** that look at both the fine internal structure of the nodule and the surrounding lung tissue context.                   |
| **Airway Segmentation**                            | Mapping the complex tree-like structure of the bronchi and trachea.                                | Utilizes **3D Fully Convolutional Networks (FCNs)** and **graph-based methods** that are refined using deep learning features.                      |
| **Interstitial Lung Disease (ILD) Classification** | Categorizing different patterns of lung tissue damage (like honeycombing or ground glass opacity). | Uses **CNNs** on image patches to identify texture patterns, often achieving performance comparable to experienced radiologists.                    |
| **Vessel & Organ Segmentation**                    | Outlining the pulmonary vessels or specific lung lobes.                                            | Employs **U-net** and other **encoder-decoder CNNs** to label pixels as part of a specific anatomical lobe or vessel.                               |
| **Pectus Excavatum Identification**                | Automatically detecting skeletal abnormalities like a sunken chest from CT scans.                  | Uses simple **CNNs** to classify specific slices of the chest scan to identify the severity of the deformity.                                       |


## Table 6
 **Breast Imaging Analysis**, a field with a long history of computer-aided detection (CAD). Recently, deep learning has significantly outperformed older "hand-crafted" systems, especially in mammography.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Mass Detection & Localization** | Finding potentially cancerous lumps in 2D mammograms or 3D tomosynthesis scans. | Uses **R-CNN (Region-based CNNs)** and **sliding-window CNNs**. Recent work (Kooi et al., 2016) has shown performance comparable to human radiologists. |
| **Lesion Classification** | Determining if a detected lump is benign (harmless) or malignant (cancerous). | Employs **pre-trained CNNs** (like AlexNet) and **transfer learning** from natural images, often combined with hand-crafted features for a "hybrid" boost. |
| **Breast Density Estimation** | Measuring the ratio of fatty tissue to dense tissue, which is a major risk factor for developing cancer. | Uses **Stacked Auto-Encoders (SAEs)** for unsupervised feature learning and **CNNs** for direct classification of density levels. |
| **Microcalcification Detection** | Finding tiny calcium deposits that can be an early sign of breast cancer. | Utilizes **CNNs** specifically trained to find very small, high-contrast objects in high-resolution images. |
| **Risk Scoring** | Analyzing "normal" mammograms to predict the future risk of a woman developing cancer years later. | Employs **CNNs** trained on historical datasets to identify subtle patterns that are invisible to the human eye but correlate with future disease. |
| **Tissue Segmentation** | Outlining the breast and fibroglandular tissue, particularly in Breast MRI. | Uses **U-net** and other pixel-wise **CNNs** to automate the measurement of tissue volumes. |

## Table 7
**Cardiac Image Analysis**, where deep learning is used to handle the dynamic, moving nature of the heart across various modalities like MRI, CT, and Ultrasound.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Ventricle Segmentation** | Delineating the left and right ventricles to calculate "ejection fraction" (how well the heart pumps). | Dominated by **U-net** and **fCNNs**. Some models use **RNNs/LSTMs** to ensure consistency as the heart moves through the cardiac cycle. |
| **Cardiac Phase Identification** | Automatically finding the exact moments of "end-diastole" (full heart) and "end-systole" (empty heart) in a video. | Uses **RNNs** and **LSTMs** to analyze the temporal sequence of images and identify specific heart-beat frames. |
| **Coronary Calcium Scoring** | Detecting and quantifying calcium buildup in the arteries, which is a major predictor of heart disease. | Employs **Multi-stream 2D CNNs** (viewing the heart from three angles) and **3D CNNs** to identify and measure calcifications. |
| **Super-Resolution** | Artificially increasing the resolution of cardiac MRI scans to see finer details of the heart muscle. | Utilizes **U-net/ResNet hybrids** to learn the mapping from low-resolution scans to high-resolution outputs. |
| **Coronary Centerline Tracking** | Automatically "tracing" the path of the coronary arteries to look for blockages. | Uses **CNNs** to classify potential paths as "correct" or "leaks," assisting in the 3D reconstruction of the arterial tree. |
| **Quality Assessment & Localization** | Checking if a cardiac exam is complete and identifying specific slices (like the apex or base) for organization. | Employs simple **CNNs** for slice-by-slice classification to ensure all parts of the heart were captured correctly. |

## Table 8
**Abdominal Image Analysis**, focusing on the major organs of the digestive and urinary systems. This area is characterized by a high degree of variability in organ shape and the frequent use of 3D CT and MRI scans.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Liver & Lesion Segmentation** | Outlining the liver and identifying tumors within it. Many studies use the SLIVER07 challenge dataset. | Primarily uses **3D CNNs**, **U-net**, and cascaded **fCNNs** often combined with **Conditional Random Fields (CRF)** to refine edges. |
| **Pancreas Segmentation** | Segmenting the pancreas, which is notoriously difficult due to its small size and high anatomical variability. | Employs **cascaded CNNs** where one network finds the general region and a second network performs the fine-grained segmentation. |
| **Kidney Segmentation & Detection** | Identifying and outlining the kidneys in CT and Ultrasound (US). | Uses **2D and 3D CNNs** often incorporating **shape priors** or active contour models to ensure anatomical consistency. |
| **Prostate Analysis** | Segmenting the prostate and classifying lesions in MRI, largely centered around the PROMISE12 challenge. | Dominated by **3D U-net** and **ResNet** architectures. Unsupervised **SAEs** and **DBNs** are also used for feature extraction from ultrasound. |
| **Colon & Polyp Detection** | Finding polyps in CT Colonography or during live Colonoscopy procedures to prevent colon cancer. | Utilizes **CNNs for false positive reduction** and pre-trained ImageNet models to generate features for **SVM classifiers**. |
| **Bladder Segmentation** | Delineating the bladder wall, which is important for staging bladder cancer. | Employs **CNN patch classification** to initialize traditional "level set" methods for precise boundary refinement. |

Table 8 demonstrates that for abdominal imaging, the field has largely moved toward "cascaded" or "multi-stage" pipelines. Because the abdomen contains many different organs packed closely together, these systems often use one deep learning model to find the organ's general location and a second, more specialized model to perform the exact pixel-level segmentation.

## Table 9
**Musculoskeletal Image Analysis**, focusing on bones, joints, and the spine. This area often deals with structural alignment, age assessment, and the detection of degenerative diseases like osteoarthritis.

| Application Category | Key Tasks and Remarks | Deep Learning Approaches |
| :--- | :--- | :--- |
| **Vertebrae Localization & Labeling** | Identifying and numbering individual vertebrae in the spine (e.g., C1, T12, L5). | Employs **3D CNNs** and **Recurrent Boltzmann Machines (RBMs)** to learn both the appearance of bones and their spatial relationship to neighbors. |
| **Bone Age Assessment** | Estimating a child's biological age by analyzing the bones in a hand X-ray. | Uses **2D regression CNNs** (like VGG) to analyze specific bones or the entire hand, often outperforming traditional atlas-based methods. |
| **Osteoarthritis Grading** | Automatically scoring the severity of knee joint degradation from X-ray images. | Primarily uses **pre-trained CNNs** (fine-tuned on ImageNet) to classify the degree of joint space narrowing and bone spurs. |
| **Vertebrae Segmentation** | Creating precise 3D maps of vertebral bodies for surgery planning or deformity analysis. | Utilizes **3D CNNs** to generate voxel-wise probabilities, which are then used to drive **deformable models** or active contours. |
| **Fracture & Metastases Detection** | Finding bone breaks or cancerous spread (sclerotic metastases) in the skeleton. | Employs **2.5D patch-based CNNs** (using multiple 2D views) to identify abnormalities while ignoring normal bone structures. |
| **Anatomical Landmark Detection** | Finding specific points on bones, such as the distal femur surface, for orthopedic measurements. | Uses **CNN-based slice classification** and intersection methods to pinpoint 3D coordinates of landmarks in MRI or CT. |

