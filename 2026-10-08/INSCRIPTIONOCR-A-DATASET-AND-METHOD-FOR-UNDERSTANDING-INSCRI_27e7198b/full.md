# INSCRIPTIONOCR: A DATASET AND METHOD FOR UNDERSTANDING INSCRIPTIONS

Jaidev Sanjay Khalane

Akbar Ali

V. N. Prabhakar

Shanmuganathan Raman

Indian Institute of Technology Gandhinagar, India.

## ABSTRACT

Ancient script image restoration is a fundamental problem in computer vision, as it directly affects the reliable analysis and interpretation of historical documents and inscriptions. Ashokan Brahmi is an ancient script extensively used during the reign of Emperor Ashoka in the 3rd century BC, primarily for inscriptions in Prakrit. These inscriptions, including major and minor rock and pillar edicts, constitute a valuable yet largely unexplored source of data for computational analysis. The degraded nature of inscription imagery and the lack of standardized digital resources pose significant challenges for automated processing. We present an end-toend AI-based framework for understanding ancient inscriptions that encompasses image enhancement, optical character recognition (OCR), transliteration, and neural machine translation (NMT). The proposed pipeline processes low-quality images captured directly from stone inscriptions, performs image restoration and Brahmi script character recognition, maps the recognized characters to the Roman script, and finally translates the resulting Prakrit text into English. We also introduce two new datasets: (i) InscriptionOCR Dataset: the largest publicly usable digital OCR dataset for Brahmi script to date, consisting of over 200,000 character images across about 600 classes, and (ii) a bilingual Prakrit-English parallel corpus comprising over 2,000 sentence pairs for NMT. We believe that the proposed framework and datasets will facilitate future research in ancient script analysis, low-resource OCR, and digital epigraphy.

Index Terms— Ancient Script OCR, Inscription Image Processing, Ancient Language Translation

## 1. INTRODUCTION

Ancient inscriptions and documents [1] constitute a vital source of historical, linguistic, and cultural knowledge. Among these, the Ashokan inscriptions dating back to the 3rd century BC represent one of the earliest and most extensive uses of writing in the Indian subcontinent [2]. These inscriptions, engraved on rocks and pillars across a vast geographical region, were primarily written in the Brahmi script and served as official proclamations of the Mauryan empire. Despite their historical significance, large-scale digitization and computational analysis of these inscriptions remain lim-

![](images/c6c1b19688a89e1a387dd77f38a80571549dd297fb1a258affd44f1fdde56db7.jpg)  
Fig. 1: Representative dataset characters.

ited.

From a computer vision perspective [3], Ashokan inscriptions present several challenges. The available images are often captured under uncontrolled environmental conditions and are prone to erosion, surface damage, uneven illumination, shadows, biological growth, and background noise. Moreover, the Brahmi [4] script exhibits significant variability in character shapes due to regional, temporal, and stylistic differences. The absence of standardized glyphs, combined with the scarcity of inscription-specific data, makes the direct application of existing optical character recognition [5] (OCR) systems ineffective.

Recent advances in digital image processing and deep learning [6] have led to substantial progress in document analysis and OCR for modern scripts. However, ancient scripts such as Brahmi remain underexplored due to the lack of publicly available datasets that support reproducible research and fair benchmarking. Most existing studies focus on isolated components, such as preprocessing or character recognition, and do not provide end-to-end datasets that span from raw inscription images to machine-readable text representations.

In this work, we present a comprehensive dataset and processing pipeline for Ashokan Brahmi inscriptions. Starting from low-quality inscription images, we apply a series of classical image processing techniques, including grayscale conversion, denoising, thresholding, contour detection, and morphological operations, to enhance and restore the visual quality of the text. The restored images are then used for character-level segmentation and OCR, employing convolutional neural network-based character recognition models.

Finally, the recognized Brahmi characters are mapped to their corresponding Roman transliterations, enabling standardized digital representation and facilitating downstream linguistic analysis [2].

The primary contribution of this paper is as follows

• A dataset-centric study bridging ancient epigraphical material with modern computer vision techniques.

• A comprehensive dataset named InscriptionOCR, specifically designed for facilitating OCR across inscription images, is also the largest Brahmi Characters dataset for OCR, both in terms of the number of classes and the number of images.

• One of the largest publicly usable datasets for the translation of text from the Prakrit language to the English language.

• An end-to-end framework to process inscription images in ancient script and language in order to return the overall content in a known language and script (English) for supporting future research in historical document analysis, and digital epigraphy.

<table><tr><td>Author</td><td>Translation</td><td>Dataset Size</td><td>OCR Classes</td><td>Translation Dataset</td></tr><tr><td>Gautam [7]</td><td>X</td><td>7,011</td><td>170</td><td>X</td></tr><tr><td>Gunasekara [4]</td><td>×</td><td>250-300</td><td>X</td><td>X</td></tr><tr><td>Mubarakkaa [5]</td><td>X</td><td>X</td><td>X</td><td>×</td></tr><tr><td>Dhivya [8]</td><td>X</td><td>190,000</td><td>209</td><td>X</td></tr><tr><td>Chaudhari [9]</td><td>√</td><td>X</td><td>X</td><td>1474</td></tr><tr><td>Our Work</td><td>√</td><td>253,800</td><td>564</td><td>2224</td></tr></table>

Table 1: Comparison of OCR and translation capabilities for Brahmi-based datasets.

<table><tr><td colspan="2">OCR Dataset</td></tr><tr><td>Total Images</td><td>253800</td></tr><tr><td>Training Images Testing Images</td><td>228,420 25,380</td></tr><tr><td>OCR Class-wise Distribution</td><td></td></tr><tr><td>Numeric Characters</td><td>30</td></tr><tr><td>Vowel Characters</td><td>17</td></tr><tr><td>Punctuation Characters</td><td>7</td></tr><tr><td>Composite Characters (Plain + Voweled Consonants)</td><td>510</td></tr><tr><td>NMT (Translation) Dataset</td><td></td></tr><tr><td>Total Parallel Sentence Pairs</td><td>2,224</td></tr><tr><td>Mean Words per Sentence (Prakrit)</td><td>~10.6</td></tr><tr><td>Mean Words per Sentence (English)</td><td>~20.8</td></tr></table>

Table 2: Specification of our proposed dataset.

## 2. RELATED WORK

The OCR of the Brahmi script is still in its early stages, primarily due to the lack of large-scale annotated datasets and the script’s complexity. Gautam et al. [7] began the work of creating a dataset of 7,011 isolated Brahmi characters in 170 classes, which served as the starting point for character-level recognition. Dhivya et al. [8] designed an OCR system for historical Tamil Brahmi script using a large-scale dataset of approximately 190,000 images and experimented with various classification architectures.

![](images/f580e2ea58c75198c37686eb83a4a738518ae7387e67544f9fb8971e06913c68.jpg)  
Fig. 2: The Stepwise Results in Image Enhancement Phase.

Other authors have experimented with smaller, less welldocumented datasets. Gunasekara et al. [4] designed a manual OCR system using a few examples of characters, while Mubarakkaa et al. [5] worked on OCR and transliteration systems for Ancient Tamil Brahmi script without mentioning the size of the dataset used.

Apart from OCR, more recent work has focused on neural machine translation (NMT) for ancient Indian languages. Chaudhari et al. [9] developed an NMT system for the Maharashtri Prakrit language using multilingual transformer models, but these models require plain text inputs and do not handle the issues arising from the degraded images of inscriptions.

Other related works on ancient scripts of other civilizations include OCR for Akkadian and Sumerian cuneiform scripts [10] and end-to-end recognition and translation of Egyptian hieroglyphs [11], which show the increasing interest in deep learning-based analysis of ancient scripts. Table 1 compares the scope and extent of the related studies and our work in the Brahmi-Prakrit domain.

## 3. DATASET

## 3.1. OCR Synthetic Dataset Generation

To mitigate the lack of large-scale, annotated data for Brahmi script recognition, we propose an automated pipeline for generating a synthetic dataset that realistically simulates ancient stone inscriptions. The clean character images are first rendered using the Unicode-compliant font NotoSansBrahmi on a 64 × 64-pixel canvas with center alignment. A stonelike background is then generated by sampling high-intensity pixel values with added Gaussian noise to simulate the granular texture of natural rock, followed by the addition of pitting artifacts and random cracks to simulate erosion and structural damage. The chiseled look of engraved characters is achieved through morphological stroke variations, beveling with spatial mask offsets, and gentle Gaussian blurring to simulate carving depth and long-term weathering. To further add variability, each sample is randomly rotated within [−20<sup>∘</sup>, +20<sup>∘</sup>] and salt-and-pepper noise is added to simulate imperfectly carved inscriptions and imaging conditions. The final images are composed by blending the chiseled character mask with the stone background, allowing the texture to remain visible within engraved regions. Using this process, we generate the InscriptionOCR dataset comprising 253,800 images (as shown in Figure 1) across 564 character classes, with 228,420 samples for training and 25,380 for testing.

## 3.2. NMT Dataset

The neural machine translation (NMT) dataset consists of 2,224 parallel sentence pairs between Prakrit and English, both represented in Roman script. The corpus was derived from the translations in [12], which present multiple Ashokan inscriptions with section-wise parallel translations.

As the source material predates modern digital publishing standards, no reliable machine-readable version of the text was available. Consequently, the Prakrit and English texts were manually captured as images and processed using the Tesseract OCR engine for Roman script recognition. Since the inscriptions contain long passages, sentence-level parallel data were extracted using the original line-level delimiters employed by the author to indicate sentence alignment. These sentence pairs were manually verified and organized to form the initial parallel corpus.

To increase data diversity, the dataset was further augmented by introducing minor lexical variations through synonym substitution while preserving semantic consistency. The final dataset comprises 2,224 sentence pairs, of which 95% were used for training and the remaining 5% for testing. The precise specifications of the OCR and NMT datasets are displayed in Table 2.

## 4. MODEL ARCHITECTURES AND METRICS

For the optical character recognition (OCR) task, several convolutional neural network (CNN) architectures were evaluated on the proposed Brahmi character dataset. The input images were grayscale with a resolution of 64 × 64, and the output layer contained 564 neurons corresponding to each character class. The LeNet-5 model [6] was employed as a lightweight baseline due to its simple architecture consisting of two convolutional layers followed by pooling operations and a sequence of fully connected layers. To explore deeper feature extraction, a VGG-16 inspired model [13] was used, comprising thirteen convolutional layers arranged in five

VGG-style blocks with roughly two to three convolutional layers each, followed by pooling, and three fully connected layers for classification. Other scalable architectures were also explored, including the ResNet-50 [3] model based on the residual learning framework, as well as highly efficient models based on the EfficientNet [14] architecture. Each of these OCR models was trained and tested on the synthetic Brahmi dataset, and detailed architectural configurations are provided in the accompanying source code.

For neural machine translation (NMT) from Prakrit (Roman script) to English, three pretrained transformer-based models were fine-tuned on the proposed parallel corpus. The Facebook M2M-100 (418M) model [15], capable of direct translation between 100 languages, including several Indian languages, was adapted via the Marathi-to-English variant for Prakrit translation. The T5-Base model [16], a 220-millionparameter text-to-text transformer, was fine-tuned from the Hindi-to-English pretrained variant, while the Helsinki-NLP OPUS model [17], also pretrained for Hindi-to-English translation, was used due to the linguistic similarity between Hindi/Marathi and Prakrit. All NMT models were trained to generate English translations from the Romanized Prakrit sentences in the parallel corpus.

The performance of the OCR models was evaluated using the testing accuracy and a few other metrics, like precision, recall, and F1-score, computed on the held-out test set to estimate generalization performance. Translation quality for the NMT models was assessed using standard metrics, namely BLEU [18] and METEOR [19] scores.

## 5. METHODOLOGY

## 5.1. Image Enhancement

To obtain a clean image suitable for downstream analysis, the original inscription image was first converted to grayscale. The grayscale image was then denoised using a Gaussian filter. After denoising, histogram-adaptive thresholding was applied to binarize the image. Morphological operations, specifically sequences of dilation and erosion applied both to the thresholded image and its inverted version, were then performed to further clean the image. Finally, the processed image was inverted to produce a clean, enhanced version suitable for OCR.

To facilitate user-friendly processing, an image preprocessing and annotation tool was developed. This application provides adjustable parameters for each stage of the enhancement pipeline, including kernel sizes and threshold values, allowing users to control the sequence and intensity of each operation. The enhanced results are visualized immediately within the app interface. When the carvings are not adequately captured or the enhancement is unsatisfactory, the user can manually annotate the inscriptions using the annotator tool. The annotator interface allows the user to upload images, select pen size, and create annotations directly on the images. Once annotations are completed, they can be downloaded for use in subsequent stages. The detailed stepwise visualization is shown in Figure 2.

## 5.2. Preprocessing for Optical Character Recognition

The annotated or enhanced images were further processed for OCR. Initially, all images were converted to grayscale (if not already), then binary thresholded, and morphologically cleaned using dilation and erosion. Contour analysis was then performed to identify regions corresponding to individual characters. Contours were filtered based on size and aspect ratio constraints to remove spurious detections, and the remaining contours were used to extract character blocks. These cropped character images were then resized to the input dimensions required by the CNN models and passed through the trained networks for classification. After classification, the detected characters were assembled into words and sentences by sorting them based on their coordinates and spacing.

## 5.3. CNN-Based Classification for OCR

For character classification, four CNN models described in the previous section were trained on the Brahmi OCR dataset. Training was performed on a 16 GB Intel i5 (12th Gen) CPU using the parameters summarized in Table 3. After training, the models were evaluated on the test dataset and subsequently used to infer the classes of individual characters extracted from inscription images.

<table><tr><td>Parameter</td><td>Value</td></tr><tr><td>Batch Size</td><td>32</td></tr><tr><td>Optimizer</td><td>Adam (Adaptive Moment Estimation)</td></tr><tr><td>Learning Rate</td><td>0.001</td></tr><tr><td>Loss Function</td><td>Categorical Cross-Entropy</td></tr><tr><td>Number of Epochs</td><td>20</td></tr></table>

Table 3: CNN training parameters.

## 5.4. Transliteration

Since the OCR outputs are in Brahmi script and Prakrit language, transliteration was required to match the Roman-script parallel dataset used for NMT. A direct mapping between Brahmi and Devanagari characters was used, followed by conversion to Roman script using the ISO transliteration scheme. After this step, the OCR outputs were represented in Romanized Prakrit, ready for translation.

## 5.5. Neural Machine Translation

For translating Romanized Prakrit to English, pretrained NMT models from Google (T5-Base), Facebook (M2M-100 418M), and Helsinki-NLP (OPUS) were fine-tuned on the parallel corpus described in the Dataset section. Fine-tuning was performed on a T4 GPU via Google Colab with the parameters summarized in Table 4. After training, these models were used to generate English translations of the transliterated OCR outputs, completing the end-to-end integrated framework from raw image to translated text.

<table><tr><td>Parameter for NMT Model Finetuning</td><td>Value</td></tr><tr><td>Learning Rate</td><td> $5 \times 1 0 ^ { - 5 }$ </td></tr><tr><td>Batch Size</td><td>8</td></tr><tr><td>Weight Decay</td><td>0.01</td></tr><tr><td>Number of Training Epochs</td><td>3</td></tr></table>

Table 4: NMT fine-tuning parameters.

## 6. RESULTS

## 6.1. End-to-End AI Integrated Framework

In this study, we developed an end-to-end AI-based framework for analyzing and translating ancient inscriptions. The framework accepts input as either a captured image of an inscription or an impression of the inscription itself. The input is first processed through the image enhancement module or, if necessary, the manual annotation module to produce a clean binary image suitable for further analysis. The enhanced image is then preprocessed for OCR, including grayscale conversion, thresholding, morphological cleaning, and contour analysis to extract individual character regions. These regions are classified using CNN-based OCR models to extract Brahmi-script text in Prakrit. Subsequently, the OCR output is transliterated from Brahmi script to Roman script, making it compatible with the parallel dataset for Neural Machine Translation. Finally, the transliterated text is processed by fine-tuned NMT models to generate the corresponding English translation. The overall flow of this integrated framework is illustrated in Figure 4, and the stepwise visual outcomes are shown in Figure 3.

## 6.2. CNN-Based Classification for OCR

The performance of the CNN-based OCR models was evaluated on the testing dataset, with results summarized in Table 5. Among the four models, ResNet achieved the highest accuracy of 100.00%, demonstrating superior performance in character classification. EfficientNet and VGG-16 also performed well, achieving test accuracies of more than 99%, closely following ResNet. In contrast, LeNet achieved a slightly lower test accuracy of approximately 88%, indicating that deeper or more optimized architectures are necessary for accurate recognition of complex Brahmi characters (Table 5).

![](images/c77fbb0eca6061ec6a8599c22e39582c12c4587514b97893763f84173a446668.jpg)  
Fig. 3: The figure illustrates the performance of the proposed method. Best viewed when zoomed in.

![](images/6f23fb7c45be3a92cbb67afe851ffe32200298c617492a5b4399fcb93ddc3a2a.jpg)  
Fig. 4: Overall flow in our Inscription Framework.

<table><tr><td>Model</td><td>Accuracy</td><td>Precision</td><td>Recall</td><td>F1 Score</td></tr><tr><td>LeNet-5</td><td>0.8872</td><td>0.8912</td><td>0.8872</td><td>0.8753</td></tr><tr><td>VGG-16</td><td>0.9939</td><td>0.9955</td><td>0.9939</td><td>0.9935</td></tr><tr><td>EfficientNet</td><td>0.9996</td><td>0.9997</td><td>0.9996</td><td>0.9996</td></tr><tr><td>ResNet-50</td><td>1.0000</td><td>1.0000</td><td>1.0000</td><td>1.0000</td></tr></table>

Table 5: Performance comparison of CNN-based OCR models.

## 6.3. Neural Machine Translation

The fine-tuned NMT models were evaluated on the test dataset using BLEU and METEOR scores, as shown in Table 6. The Facebook M2M-100 418M model achieved the highest performance, with BLEU and METEOR scores of 56.367 and 0.772, respectively, significantly outperforming the other models. The Helsinki-NLP Opus model achieved a BLEU score of 14.120 and a METEOR score of 0.254, while the Google T5 Base model showed lower performance, with a BLEU score of 7.75 and a METEOR score of 0.093.

These results indicate that the M2M-100 model is best suited for translating Romanized Prakrit into English within our framework (Table 6).

<table><tr><td>Model Name</td><td>BLEU Score</td><td>METEOR Score</td></tr><tr><td>M2M 100 418M</td><td>56.367</td><td>0.772</td></tr><tr><td>t5 Base</td><td>7.750</td><td>0.093</td></tr><tr><td>Helsinki-NLP Opus</td><td>14.120</td><td>0.254</td></tr></table>

Table 6: NMT training results.

## 6.4. Conclusion

In this study, we successfully achieved the dual objectives of creating extensive datasets for OCR of Brahmi characters and neural machine translation of Prakrit. Building on these datasets, we developed an end-to-end AI-based framework for translating ancient inscriptions, encompassing image enhancement, OCR, transliteration, and NMT. To facilitate practical use, we also implemented web applications that allow users to obtain translations directly from inscription images through a convenient interface.

This study provides novel, large-scale datasets for Brahmi OCR (InscriptionOCR Dataset) and for Prakrit-to-English translation. Additionally, it presents a fully integrated AI framework designed for understanding ancient inscriptions. The framework and its applications provide valuable tools for scholars, linguists, and heritage preservationists. This represents a significant advancement towards the computational revival and analysis of ancient languages and scripts.

## 7. REFERENCES

[1] Agam Dwivedi, Rohit Saluja, and Ravi Kiran Sarvadevabhatla, “An ocr for classical indic documents containing arbitrarily long words,” in Proceedings of the IEEE/CVF CVPR Workshops, 2020, pp. 560–561.

[2] Yuqing Zhang, Hangqi Li, Shengyu Zhang, Runzhong Wang, Baoyi He, Huaiyong Dou, Junchi Yan, Yongquan Zhang, and Fei Wu, “Llmco4mr: Llms-aided neural combinatorial optimization for ancient manuscript restoration from fragments with case studies on dunhuang,” in ECCV. Springer, 2024, pp. 253–269.

[3] Kaiming He, Xiangyu Zhang, Shaoqing Ren, and Jian Sun, “Deep residual learning for image recognition,” in Proceedings ofthe IEEE conference on computer vision and pattern recognition, 2016, pp. 770–778.

[4] Sakith Gunasekara, Muhammed Haleef Lafir, Chavindu Dulaj, Lakidu Haputhanthri, and Dileeka Alwis, “Deep learning-powered mobile app for early brahmi script decipherment in sri lanka,” in 2024 International Research Conference on Smart Computing and Systems Engineering (SCSE). IEEE, 2024, vol. 7, pp. 1–6.

[5] M Fathima Mubarakkaa, M Nandhini, M Keerthika, and Haripriya Ganapathy, “Ocr based transliteration of brahmi to tamil using cnn,” in 2024 International Conference on Power, Energy, Control and Transmission Systems (ICPECTS). IEEE, 2024, pp. 1–5.

[6] Yann LeCun, Léon Bottou, Yoshua Bengio, and Patrick Haffner, “Gradient-based learning applied to document recognition,” Proceedings of the IEEE, vol. 86, no. 11, pp. 2278–2324, 2002.

[7] Neha Gautam, Soo See Chai, and Megha Gautam, “The dataset for printed brahmi word recognition,” in Micro-Electronics and Telecommunication Engineering: Proceedings of 3rd ICMETE 2019, pp. 125–133. Springer, 2020.

[8] S Dhivya and Usha G Devi, “Tamizhi: historical tamilbrahmi script recognition using cnn and mobilenet,” ACM Transactions on Asian and Low-Resource Language Information Processing, vol. 20, no. 3, 2021.

[9] Sarvesh M Chaudhari, Sankalp R Chakre, Nirdosh D Chavhan, Adwait A Gondhalekar, Kishor R Pathak, and Manohar K Kodmelwar, “Bridging the past: Neural machine translation of maharashtri prakrit to english,” in International Conference on Data Science, Computation and Security. Springer, 2024, pp. 541–549.

[10] Shai Gordin, Morris Alper, Avital Romach, Luis Saenz Santos, Naama Yochai, and Roey Lalazar, “Cured: Deep learning optical character recognition for cuneiform text editions and legacy materials,” in Proceedings ofthe 1st Workshop on Machine Learning for Ancient Languages (ML4AL 2024), 2024, pp. 130–140.

[11] Asmaa Sobhy, Mahmoud Helmy, Michael Khalil, Sarah Elmasry, Youtham Boules, and Nermin Negied, “An ai based automatic translator for ancient hieroglyphic language—from scanned images to english text,” IEEE Access, vol. 11, pp. 38796–38804, 2023.

[12] E. Hultzsch, Corpus Inscriptionum Indicarum. Vol. 1: Inscriptions of Asoka ´ , Archaeological Survey of India, 1991.

[13] Karen Simonyan and Andrew Zisserman, “Very deep convolutional networks for large-scale image recognition,” arXiv preprint arXiv:1409.1556, 2014.

[14] Mingxing Tan and Quoc Le, “Efficientnet: Rethinking model scaling for convolutional neural networks,” in International conference on machine learning. PMLR, 2019, pp. 6105–6114.

[15] Angela Fan, Shruti Bhosale, Holger Schwenk, Zhiyi Ma, Ahmed El-Kishky, Siddharth Goyal, Mandeep Baines, Onur Celebi, Guillaume Wenzek, Vishrav Chaudhary, et al., “Beyond english-centric multilingual machine translation,” Journal of Machine Learning Research, vol. 22, no. 107, pp. 1–48, 2021.

[16] Colin Raffel, Noam Shazeer, Adam Roberts, Katherine Lee, Sharan Narang, Michael Matena, Yanqi Zhou, Wei Li, and Peter J Liu, “Exploring the limits of transfer learning with a unified text-to-text transformer,” Journal of machine learning research, vol. 21, no. 140, pp. 1–67, 2020.

[17] Jörg Tiedemann, Mikko Aulamo, Daria Bakshandaeva, Michele Boggia, Stig-Arne Grönroos, Tommi Nieminen, Alessandro Raganato Yves Scherrer, Raul Vazquez, and Sami Virpioja, “Democratizing neural machine translation with OPUS-MT,” Language Resources and Evaluation, , no. 58, pp. 713–755, 2023.

[18] Kishore Papineni, Salim Roukos, Todd Ward, and Wei-Jing Zhu, “Bleu: a method for automatic evaluation of machine translation,” in Proceedings ofthe 40th annual meeting of the Association for Computational Linguistics, 2002, pp. 311–318.

[19] Satanjeev Banerjee and Alon Lavie, “Meteor: An automatic metric for mt evaluation with improved correlation with human judgments,” in Proceedings of the acl workshop on intrinsic and extrinsic evaluation measures for machine translation and/or summarization, 2005, pp. 65–72.

[20] Photo Dharma, “Buddha Sakyamuni on the Rummindei pillar of Ashoka,” [Online], Available: https: //commons.wikimedia.org/wiki/File: Buddha\_Sakyamuni\_on\_the\_Rummindei\_ pillar\_of\_Ashoka.jpg, 2018, [Accessed] Dec. 19, 2025.

[21] Ashok Tapase, “Devanampriyasa Asoka Text on Maski Edict,” [Online], Available: https: //commons.wikimedia.org/wiki/File: Devanampriyasa\_Asoka.jpg, 2018, [Accessed] Dec. 19, 2025.

# Supplementary Material

## 8. DATASET DOCUMENTATION

## Description

This is the dataset for the Inscription Intelligence Project. The dataset contains two sections, one for the OCR of Brahmi Characters, also specialised towards inscriptions and the second one for NMT having parallel sentence pairs between Prakrit and English.

## Code

GitHub repository

## Dataset

Kaggle dataset

## Data Subject(s)

Character Image Classification (OCR), Neural Machine Translation

## Volume

Approximately 650 MB.

## Total Number of Images

The OCR dataset comprises more than 250,000 images. The NMT dataset is in csv format with about 2000 sentence pairs.

## Data Format

OCR Data: png images, NMT Data: csv format.

## Dataset Owner and Affiliation

Indian Institute of Technology Gandhinagar, India.

## Dataset Organization

The OCR Data has separate folders for testing and training samples which again contain separate folders for every character, named by the character and contains the respective images. The NMT Data is in the form of a csv file with two columns, the first one being the Prakrit text in Roman Script and the second one being its corresponding translation in English.

## License

ATTRIBUTION-NONCOMMERCIAL 4.0 INTERNATIONAL

## 9. IMPLEMENTATION DETAILS

The supplementary document provides additional analyses in terms of various inscription datasets, restoration scenarios, and levels of degradation. Taken together, these analyses provide further insights into the performance characteristics of the proposed approach for restoring ancient inscription images.

## 9.1. Dataset Generation

For the generation of synthetic dataset similar to the that of ancient inscriptions, we use computer vision techniques to simulate how these ancient characters might appear when carved into stone and weathered by time.

The synthesis of the Brahmi dataset begins with the create\_character\_image function, which establishes a clean baseline by rendering characters onto a 64×64 pixel white canvas. To maintain linguistic accuracy, the NotoSansBrahmi font is utilized for proper Unicode support, while the usage of anchor ensures that the glyph remains centered for subsequent transformations. To move beyond digital perfection, the script simulates an authentic stone surface by generating a base texture with pixel values between 220 and 240, enriched with Gaussian noise, structural fissures via the generate\_cracks function, and porous "pitting"

The "chiseled" aesthetic is achieved through the apply\_stone\_augmentations function, where MinFilter and MaxFilter randomly erode or dilate strokes to replicate varying tool pressure. By offsetting the character mask to create beveling and   
applying a slight Gaussian blur to simulate centuries of weathering, the script transforms flat text into a recessed 3D engraving.   
To ensure the final machine learning model is robust, the pipeline introduces dataset diversification through random rotations between $[ - 2 0 ^ { \circ } , + 2 0 ^ { \circ } ]$ , the addition of salt-and-pepper noise, and complex composition techniques. This rigorous process ultimately produced a comprehensive dataset of more than 200,000 images as described previously across 564 classes.

## 9.2. Image Enhancement

In this subsection, we will display the figures corresponding to the image enhancement as described in the main text. Figure 5a displays the original image, while Figure 5b displays the results of intermediate steps such as Grayscaling, Filtering (Gaussian Blurring), Adaptive Thresholding, Cycles of Dilation, Erosion and Inversion as well as the Final Image.

Original Image  
![](images/c24b92d47066612063662895c2d8ff59fbdc190614ccab4a701a65984f9bf6e4.jpg)  
(a) Original Image. Derived from: [20]

![](images/2bea6c897cd0131fc24f9ef196710eb7af6393198888df428204a13ea7e6f014.jpg)

![](images/eba029a0060247ba21ed26ba01b2bda34277053e3183f94d21520d51b1cf4283.jpg)

![](images/172d7de3c10113760553a1c704fc1de89ff1437da5457be41a7962956f70fae7.jpg)

![](images/e6379c67f2a80ccac6a6b00e70410530f20356bbb13dafa4aa68d1289ce9960e.jpg)

![](images/b94089783798d52fbd5d2bf729afde262be31ae08fd9884c8042b2d0575448fa.jpg)  
(b) Stepwise Results in Image Enhancement Phase

![](images/8ad74f876650127e8fd7331c7d3bdf46db8ccceee4f5e2da31a57c66586db648.jpg)  
Fig. 5: Comparison of the Original Image and Image Enhancement Results

## 9.3. Preprocessing for OCR

In this subsection, we present the intermediate results in the preprocessing required before the OCR step. Figure 6a shows the initial image which was further prepared for OCR by performing Grayscaling, Thresholding and Cleaning through   
Morphological Operations like Erosion and Dilation as displayed in Figure 6b. Figure 6c displays the identified contours over the preprocessed image which will be cropped and passed to the CNN for further classification.

![](images/6b364787c77389402d02bf816ab18ce30a240960a3930cf7e189a96d73b750b0.jpg)  
(a) Original Image (Obtained as Inscription Impression) [12]

![](images/021236aff58df3280194d15fd6f437a073d7b71538eeff47da890de2cf0d6084.jpg)  
(b) Preprocessing Steps before OCR

![](images/fed4e0a0b436b13a82d07b89c6346a8f113500410daf3f3214a8d722469b7ecb.jpg)  
(c) Contour Identification during OCR  
Fig. 6: OCR Processing Pipeline for Inscription Images

![](images/42d907ab7b8b2aaa2820a5c202976302f02f3c43e94542a2ee3085e4f1a6c995.jpg)  
Fig. 7: Image Enhancement Application Interface and Output Result

## 10. APPLICATIONS FOR INSCRIPTION UNDERSTANDING

## 10.1. Image Enhancement

In order to make the image enhancement framework easy to use, a streamlit application was also developed as shown in Figure 7a. The resultant image obtained can be downloaded by the user as shown in 7b.

## 10.2. Image Annotation Application

In case the user is not satisfied with the image enhanced by the previous application, they can also manually annotate the image to trace the text written. Figure 8a shows the original image. Figure 8b shows the interface of our image annotation application. The image can then be uploaded to this application and the user can annotate this as shown in Figure 8c. Finally, the user can download the annotation as in Figure 8d and use it in the further steps.

![](images/c2eb8f4c3082a77dd5cdf44cd451cd864cae90b31074324ef93534ffcb1dc4f7.jpg)

![](images/a66b733f171b1e067d0bdd1644908825dce6811e11fbad77f7041128f165686f.jpg)  
(b) Annotation Application Interface

(a) Original Image [21]  
![](images/e1bd3f4a61200bb3b19d3fab0297678ca24b29eb2bb852ac2dc673e41cb788a7.jpg)  
(c) Image Being Annotated in the Application

![](images/d82aeb2d6700dfc32ffcd488eaad3bc3c72e6ad95cdfb2a39c610122552aabc7.jpg)  
(d) Downloaded Annotation  
Fig. 8: Image Annotation Process and Results

## 10.3. OCR+NMT Application

To make the integrated framework accessible to users, a web application was developed using Flask (Python). This application allows users to upload enhanced images of inscriptions and receive the corresponding English translation, integrating the OCR, transliteration, and NMT modules in a seamless workflow. Since the computationally intensive operations are   
performed on the server, users can access the application via mobile devices, broadening its accessibility. The mobile interface and workflow for uploading and obtaining translations are illustrated in Figs. 9a and 9b.

![](images/cff96cd53f89235e3f4529a3c1d83162402df029765d98c63617e6b5efea5f95.jpg)  
(a) Mobile Application Interface for the Framework and Menu for Uploading the Image

![](images/6df73dc9c72cfd84d17f237f69bd0a1e81d796c8b2903285b58809b7b86e1366.jpg)  
(b) Overall Result of OCR + Transliteration + NMT (Mobile Screenshot)  
Fig. 9: Mobile Application Interface and OCR+Transliteration+NMT Output