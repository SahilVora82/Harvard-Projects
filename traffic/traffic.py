import cv2
import numpy as np
import os
import sys
import tensorflow as tf

from sklearn.model_selection import train_test_split

EPOCHS = 10
IMG_WIDTH = 32
IMG_HEIGHT = 32
NUM_CATEGORIES = 43
TEST_SIZE = 0.4


def main():

    # Check command-line arguments
    if len(sys.argv) not in [2, 3]:
        sys.exit("Usage: python traffic.py data_directory [model.h5]")

    # Get image arrays and labels for all image files
    images, labels = load_data(sys.argv[1])

    # Split data into training and testing sets
    labels = tf.keras.utils.to_categorical(labels)
    x_train, x_test, y_train, y_test = train_test_split(
        np.array(images), np.array(labels), test_size=TEST_SIZE
    )

    # Get a compiled neural network
    model = get_model()

    # Fit model on training data
    model.fit(x_train, y_train, epochs=EPOCHS)

    # Evaluate neural network performance
    model.evaluate(x_test,  y_test, verbose=2)

    # Save model to file
    if len(sys.argv) == 3:
        filename = sys.argv[2]
        model.save(filename)
        print(f"Model saved to {filename}.")


def load_data(data_dir):
    """
    Load image data from directory `data_dir`.

    Assume `data_dir` has one directory named after each category, numbered
    0 through NUM_CATEGORIES - 1. Inside each category directory will be some
    number of image files.

    Return tuple `(images, labels)`. `images` should be a list of all
    of the images in the data directory, where each image is formatted as a
    numpy ndarray with dimensions IMG_WIDTH x IMG_HEIGHT x 3. `labels` should
    be a list of integer labels, representing the categories for each of the
    corresponding `images`.
    """

    images = []
    labels = []

    # Get names of directories containing the category files
    categories_in_data = os.listdir(data_dir)

    for category in categories_in_data:

        # Skip hidden files like .DS_Store
        if category.startswith("."):
            continue

        # Combine path to gtsrb with category file
        path_to_category = os.path.join(data_dir,category)

        images_in_category = os.listdir(path_to_category)

        # For each image in the category,
        for image in images_in_category:

            # Get the path to the image
            path_to_image = os.path.join(path_to_category, image)

            # Read/save image and resize it.
            current_image = cv2.imread(path_to_image)
            resized_image = cv2.resize(current_image, (IMG_WIDTH,IMG_HEIGHT))

            images.append(resized_image)
            labels.append(int(category))

    return images, labels


def get_model():
    """
    Returns a compiled convolutional neural network model. Assume that the
    `input_shape` of the first layer is `(IMG_WIDTH, IMG_HEIGHT, 3)`.
    The output layer should have `NUM_CATEGORIES` units, one for each category.
    """

    model = tf.keras.Sequential([
        tf.keras.Input(shape=(IMG_WIDTH, IMG_HEIGHT, 3)), # Input layer

        tf.keras.layers.Rescaling(scale=1. / 255), # Normalize image from 0 to 1

        # First block of convolution
        tf.keras.layers.Conv2D(64, 3, padding= "same"),
        tf.keras.layers.LeakyReLU(alpha = 0.1),
        tf.keras.layers.MaxPooling2D(2),
        tf.keras.layers.SpatialDropout2D(0.05),

        # Second block of convolution
        tf.keras.layers.Conv2D(64, 3,padding = "same" ),
        tf.keras.layers.LeakyReLU(alpha=0.1),
        tf.keras.layers.MaxPooling2D(2),
        tf.keras.layers.SpatialDropout2D(0.05),



        tf.keras.layers.Flatten(),
        tf.keras.layers.Dense(NUM_CATEGORIES, activation="softmax") # Output layer with 43 units
    ])

    # Compiling the model. Used Stochastic Gradient Descent
    model.compile(optimizer= tf.keras.optimizers.SGD(learning_rate = 0.15, momentum = 0.5),
                  loss= tf.keras.losses.CategoricalCrossentropy(),
                  metrics= ["accuracy"]
                )

    return model

if __name__ == "__main__":
    main()
